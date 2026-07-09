---
title: "Autoencoders — Undercomplete, Denoising, Sparse, Contractive"
slug: "autoencoders"
description: "A comprehensive guide to autoencoder variants: undercomplete bottlenecks, denoising autoencoders as score function estimators, sparse autoencoders with L1 and KL penalties, contractive autoencoders with Jacobian regularisation, and the connection to PCA and VAEs."
tags: ["unsupervised-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"An autoencoder is a neural network trained to reconstruct its input through a compressed bottleneck. The encoder f: X→Z maps input to a latent code, the decoder g: Z→X̂ maps back to input space, and training minimises the reconstruction loss ‖x - g(f(x))‖². Different regularisation strategies produce qualitatively different latent representations."},{"type":"heading","level":2,"content":"Architecture and Reconstruction Loss"},{"type":"text","content":"The simplest autoencoder uses a single bottleneck hidden layer: x → h (encoder) → x̂ (decoder), with MSE loss ‖x-x̂‖² for continuous inputs or binary cross-entropy for binary inputs. The bottleneck dimension d_z \u003c d_x forces compression. The key insight: a linear autoencoder with MSE loss recovers exactly the PCA subspace — it finds the same directions of maximum variance."},{"type":"heading","level":2,"content":"Undercomplete Autoencoder vs PCA"},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nfrom sklearn.datasets import load_digits\nfrom sklearn.decomposition import PCA\nfrom sklearn.preprocessing import StandardScaler\n\nX, y = load_digits(return_X_y=True)\nX = StandardScaler().fit_transform(X).astype(np.float32)\nX_t = torch.tensor(X)\n\nclass Autoencoder(nn.Module):\n    def __init__(self, input_dim=64, latent_dim=2):\n        super().__init__()\n        self.encoder = nn.Sequential(\n            nn.Linear(input_dim, 32), nn.ReLU(),\n            nn.Linear(32, latent_dim)\n        )\n        self.decoder = nn.Sequential(\n            nn.Linear(latent_dim, 32), nn.ReLU(),\n            nn.Linear(32, input_dim)\n        )\n    def forward(self, x):\n        return self.decoder(self.encoder(x))\n\nmodel = Autoencoder(latent_dim=2)\nopt = torch.optim.Adam(model.parameters(), lr=1e-3)\nfor epoch in range(300):\n    loss = nn.MSELoss()(model(X_t), X_t)\n    opt.zero_grad(); loss.backward(); opt.step()\n    if epoch % 100 == 0:\n        print(f\u0027Epoch {epoch}: loss={loss.item():.4f}\u0027)\n\nwith torch.no_grad():\n    Z_ae = model.encoder(X_t).numpy()\nZ_pca = PCA(n_components=2).fit_transform(X)\nprint(f\u0027AE latent shape: {Z_ae.shape},  PCA shape: {Z_pca.shape}\u0027)"},{"type":"heading","level":2,"content":"Denoising Autoencoder"},{"type":"text","content":"A denoising autoencoder (DAE) trains on corrupted inputs x̃ and reconstructs the clean x. The corruption can be Gaussian noise, masking (dropout), or salt-and-pepper noise. The key insight (Vincent et al. 2011): the DAE learns to estimate the gradient of the log data density ∂log p(x)/∂x — a score function. This forces the model to understand the data manifold rather than just memorising inputs."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nfrom sklearn.datasets import load_digits\nfrom sklearn.preprocessing import MinMaxScaler\n\nX, y = load_digits(return_X_y=True)\nX = MinMaxScaler().fit_transform(X).astype(np.float32)\nX_t = torch.tensor(X)\nnoise_std = 0.3\n\nclass DenoisingAE(nn.Module):\n    def __init__(self, dim=64):\n        super().__init__()\n        self.enc = nn.Sequential(\n            nn.Linear(dim, 128), nn.ReLU(),\n            nn.Linear(128, 32), nn.ReLU()\n        )\n        self.dec = nn.Sequential(\n            nn.Linear(32, 128), nn.ReLU(),\n            nn.Linear(128, dim), nn.Sigmoid()\n        )\n    def forward(self, x):\n        return self.dec(self.enc(x))\n\nmodel = DenoisingAE()\nopt = torch.optim.Adam(model.parameters(), lr=1e-3)\n\nfor epoch in range(300):\n    noise = torch.randn_like(X_t) * noise_std\n    X_noisy = torch.clamp(X_t + noise, 0.0, 1.0)  # corrupt\n    X_recon = model(X_noisy)                        # reconstruct\n    loss = nn.MSELoss()(X_recon, X_t)               # target: clean!\n    opt.zero_grad(); loss.backward(); opt.step()\n    if epoch % 100 == 0:\n        print(f\u0027Epoch {epoch}: loss={loss.item():.4f}\u0027)\n\nwith torch.no_grad():\n    noise = torch.randn_like(X_t[:8]) * noise_std\n    X_noisy_test = torch.clamp(X_t[:8] + noise, 0, 1)\n    X_clean = model(X_noisy_test)\nprint(f\u0027Denoising MSE: {nn.MSELoss()(X_clean, X_t[:8]).item():.4f}\u0027)"},{"type":"callout","variant":"info","title":"Denoising AE and Score Matching","content":"The optimal DAE output satisfies E[x | x̃] ≈ x̃ + σ² ∂log p(x̃)/∂x̃. This means the DAE implicitly estimates the score function of the data distribution — the same quantity used in score-based generative models and diffusion models."},{"type":"heading","level":2,"content":"Sparse Autoencoder"},{"type":"text","content":"A sparse autoencoder uses an overcomplete representation (d_z \u003e d_x) but forces sparse activations via an L1 penalty or a KL divergence between the average activation and a target sparsity ρ. Unlike undercomplete AEs, sparsity (not bottleneck size) provides the compression pressure. Sparse features tend to be more interpretable and disentangled."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nfrom sklearn.datasets import load_digits\nfrom sklearn.preprocessing import MinMaxScaler\n\nX, y = load_digits(return_X_y=True)\nX = MinMaxScaler().fit_transform(X).astype(np.float32)\nX_t = torch.tensor(X)\n\nclass SparseAE(nn.Module):\n    def __init__(self, input_dim=64, hidden_dim=256):\n        super().__init__()\n        # Overcomplete: hidden_dim \u003e input_dim\n        self.encoder = nn.Sequential(nn.Linear(input_dim, hidden_dim), nn.ReLU())\n        self.decoder = nn.Linear(hidden_dim, input_dim)\n    def forward(self, x):\n        h = self.encoder(x)\n        return self.decoder(h), h\n\nmodel = SparseAE(hidden_dim=256)\nopt = torch.optim.Adam(model.parameters(), lr=1e-3)\nlambda_l1 = 1e-4\n\nfor epoch in range(300):\n    x_recon, h = model(X_t)\n    recon_loss = nn.MSELoss()(x_recon, X_t)\n    sparse_loss = lambda_l1 * h.abs().mean()  # L1 sparsity on activations\n    loss = recon_loss + sparse_loss\n    opt.zero_grad(); loss.backward(); opt.step()\n    if epoch % 100 == 0:\n        active_frac = (h.detach() \u003e 0.1).float().mean().item()\n        print(f\u0027Epoch {epoch}: recon={recon_loss:.4f}, active={active_frac:.1%}\u0027)\n\nwith torch.no_grad():\n    _, h = model(X_t)\n    print(f\u0027Average active units: {(h \u003e 0.1).float().mean():.1%}\u0027)"},{"type":"heading","level":2,"content":"Contractive Autoencoder"},{"type":"text","content":"A contractive autoencoder (CAE) penalises the Frobenius norm of the encoder Jacobian ‖∂h/∂x‖_F². This forces the encoder to be insensitive to small perturbations of the input — the latent code changes slowly as x moves slightly. For a sigmoid encoder, the Jacobian penalty simplifies to Σⱼ h_j²(1-h_j)² Σᵢ W_ji², which is cheap to compute analytically."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nfrom sklearn.datasets import load_digits\nfrom sklearn.preprocessing import MinMaxScaler\n\nX, y = load_digits(return_X_y=True)\nX = MinMaxScaler().fit_transform(X).astype(np.float32)\nX_t = torch.tensor(X)\nd_in, d_h = 64, 32\n\nclass ContractiveAE(nn.Module):\n    def __init__(self):\n        super().__init__()\n        self.enc_layer = nn.Linear(d_in, d_h)\n        self.dec = nn.Sequential(nn.Linear(d_h, d_in), nn.Sigmoid())\n    def forward(self, x):\n        h = torch.sigmoid(self.enc_layer(x))\n        return self.dec(h), h\n\ndef jacobian_frob(h, W):\n    # Analytic Frobenius norm for sigmoid encoder\n    s = h * (1.0 - h)               # (n, d_h) — sigmoid derivative\n    return (s**2 @ (W**2).sum(dim=1)).mean()\n\nmodel = ContractiveAE()\nopt = torch.optim.Adam(model.parameters(), lr=1e-3)\nlambda_c = 1e-4\n\nfor epoch in range(300):\n    x_recon, h = model(X_t)\n    recon = nn.MSELoss()(x_recon, X_t)\n    contract = lambda_c * jacobian_frob(h, model.enc_layer.weight)\n    loss = recon + contract\n    opt.zero_grad(); loss.backward(); opt.step()\n    if epoch % 100 == 0:\n        print(f\u0027Epoch {epoch}: recon={recon:.4f}, contract={contract:.6f}\u0027)\nprint(\u0027Training complete\u0027)"},{"type":"heading","level":2,"content":"Linear AE = PCA, and VAE Preview"},{"type":"text","content":"A linear autoencoder with MSE loss (no nonlinearities) spans the same subspace as PCA: the learned encoder directions are the top k eigenvectors of XᵀX. They may be rotated relative to the true PCs, but the subspace is identical. The VAE (Variational Autoencoder) extends this framework probabilistically: the encoder outputs a distribution q(z|x) = N(μ(x), σ²(x)) and the loss adds a KL term to enforce a smooth, continuous latent space — enabling generation."},{"type":"list","ordered":false,"items":["Undercomplete AE: compression via bottleneck; equivalent to PCA when linear","Denoising AE: corruption + reconstruction; learns data manifold and score function","Sparse AE: overcomplete + L1 or KL penalty; disentangled, interpretable features","Contractive AE: Jacobian penalty; stable latent code invariant to perturbations","VAE: probabilistic encoder; continuous, generative latent space"]},{"type":"table","headers":["Variant","Regularisation","Latent Structure","Best For"],"rows":[["Undercomplete","Bottleneck size","Compact, dense","Dimensionality reduction"],["Denoising","Input corruption","Manifold-aligned","Robust features, image restoration"],["Sparse","L1 or KL on activations","Sparse, overcomplete","Interpretable features, dictionary learning"],["Contractive","Jacobian Frobenius","Smooth, stable","Noise-robust representations"],["VAE","KL(q(z|x)||p(z))","Continuous, generative","Generation, interpolation"]]},{"type":"text","content":"All autoencoder variants share the encoder-decoder skeleton but differ in what they regularise. The choice of regularisation determines the geometry of the latent space: a bottleneck produces a compact subspace (like PCA), corruption pressure produces a manifold-aligned code, L1 penalty produces a sparse dictionary, and Jacobian penalty produces a flat, locally-linear mapping. Each regularisation strategy is suited to a different downstream goal."},{"type":"divider"},{"type":"callout","variant":"tip","title":"Choosing an Autoencoder Variant","content":"For dimensionality reduction comparable to PCA: undercomplete AE. For learning representations that generalise under noise: denoising AE. For human-interpretable features: sparse AE. For smooth latent spaces needed for interpolation or generation: VAE. For production feature extractors that are stable under input perturbations: contractive AE."}]"
---
# Autoencoders — Undercomplete, Denoising, Sparse, Contractive

An autoencoder is a neural network trained to reconstruct its input through a compressed bottleneck. The encoder f: X→Z maps input to a latent code, the decoder g: Z→X̂ maps back to input space, and training minimises the reconstruction loss ‖x - g(f(x))‖². Different regularisation strategies produce qualitatively different latent representations.

## Architecture and Reconstruction Loss

The simplest autoencoder uses a single bottleneck hidden layer: x → h (encoder) → x̂ (decoder), with MSE loss ‖x-x̂‖² for continuous inputs or binary cross-entropy for binary inputs. The bottleneck dimension d_z < d_x forces compression. The key insight: a linear autoencoder with MSE loss recovers exactly the PCA subspace — it finds the same directions of maximum variance.

## Undercomplete Autoencoder vs PCA

```python
import numpy as np
import torch
import torch.nn as nn
from sklearn.datasets import load_digits
from sklearn.decomposition import PCA
from sklearn.preprocessing import StandardScaler

X, y = load_digits(return_X_y=True)
X = StandardScaler().fit_transform(X).astype(np.float32)
X_t = torch.tensor(X)

class Autoencoder(nn.Module):
    def __init__(self, input_dim=64, latent_dim=2):
        super().__init__()
        self.encoder = nn.Sequential(
            nn.Linear(input_dim, 32), nn.ReLU(),
            nn.Linear(32, latent_dim)
        )
        self.decoder = nn.Sequential(
            nn.Linear(latent_dim, 32), nn.ReLU(),
            nn.Linear(32, input_dim)
        )
    def forward(self, x):
        return self.decoder(self.encoder(x))

model = Autoencoder(latent_dim=2)
opt = torch.optim.Adam(model.parameters(), lr=1e-3)
for epoch in range(300):
    loss = nn.MSELoss()(model(X_t), X_t)
    opt.zero_grad(); loss.backward(); opt.step()
    if epoch % 100 == 0:
        print(f'Epoch {epoch}: loss={loss.item():.4f}')

with torch.no_grad():
    Z_ae = model.encoder(X_t).numpy()
Z_pca = PCA(n_components=2).fit_transform(X)
print(f'AE latent shape: {Z_ae.shape},  PCA shape: {Z_pca.shape}')
```

## Denoising Autoencoder

A denoising autoencoder (DAE) trains on corrupted inputs x̃ and reconstructs the clean x. The corruption can be Gaussian noise, masking (dropout), or salt-and-pepper noise. The key insight (Vincent et al. 2011): the DAE learns to estimate the gradient of the log data density ∂log p(x)/∂x — a score function. This forces the model to understand the data manifold rather than just memorising inputs.

```python
import numpy as np
import torch
import torch.nn as nn
from sklearn.datasets import load_digits
from sklearn.preprocessing import MinMaxScaler

X, y = load_digits(return_X_y=True)
X = MinMaxScaler().fit_transform(X).astype(np.float32)
X_t = torch.tensor(X)
noise_std = 0.3

class DenoisingAE(nn.Module):
    def __init__(self, dim=64):
        super().__init__()
        self.enc = nn.Sequential(
            nn.Linear(dim, 128), nn.ReLU(),
            nn.Linear(128, 32), nn.ReLU()
        )
        self.dec = nn.Sequential(
            nn.Linear(32, 128), nn.ReLU(),
            nn.Linear(128, dim), nn.Sigmoid()
        )
    def forward(self, x):
        return self.dec(self.enc(x))

model = DenoisingAE()
opt = torch.optim.Adam(model.parameters(), lr=1e-3)

for epoch in range(300):
    noise = torch.randn_like(X_t) * noise_std
    X_noisy = torch.clamp(X_t + noise, 0.0, 1.0)  # corrupt
    X_recon = model(X_noisy)                        # reconstruct
    loss = nn.MSELoss()(X_recon, X_t)               # target: clean!
    opt.zero_grad(); loss.backward(); opt.step()
    if epoch % 100 == 0:
        print(f'Epoch {epoch}: loss={loss.item():.4f}')

with torch.no_grad():
    noise = torch.randn_like(X_t[:8]) * noise_std
    X_noisy_test = torch.clamp(X_t[:8] + noise, 0, 1)
    X_clean = model(X_noisy_test)
print(f'Denoising MSE: {nn.MSELoss()(X_clean, X_t[:8]).item():.4f}')
```

> **Denoising AE and Score Matching**: The optimal DAE output satisfies E[x | x̃] ≈ x̃ + σ² ∂log p(x̃)/∂x̃. This means the DAE implicitly estimates the score function of the data distribution — the same quantity used in score-based generative models and diffusion models.

## Sparse Autoencoder

A sparse autoencoder uses an overcomplete representation (d_z > d_x) but forces sparse activations via an L1 penalty or a KL divergence between the average activation and a target sparsity ρ. Unlike undercomplete AEs, sparsity (not bottleneck size) provides the compression pressure. Sparse features tend to be more interpretable and disentangled.

```python
import numpy as np
import torch
import torch.nn as nn
from sklearn.datasets import load_digits
from sklearn.preprocessing import MinMaxScaler

X, y = load_digits(return_X_y=True)
X = MinMaxScaler().fit_transform(X).astype(np.float32)
X_t = torch.tensor(X)

class SparseAE(nn.Module):
    def __init__(self, input_dim=64, hidden_dim=256):
        super().__init__()
        # Overcomplete: hidden_dim > input_dim
        self.encoder = nn.Sequential(nn.Linear(input_dim, hidden_dim), nn.ReLU())
        self.decoder = nn.Linear(hidden_dim, input_dim)
    def forward(self, x):
        h = self.encoder(x)
        return self.decoder(h), h

model = SparseAE(hidden_dim=256)
opt = torch.optim.Adam(model.parameters(), lr=1e-3)
lambda_l1 = 1e-4

for epoch in range(300):
    x_recon, h = model(X_t)
    recon_loss = nn.MSELoss()(x_recon, X_t)
    sparse_loss = lambda_l1 * h.abs().mean()  # L1 sparsity on activations
    loss = recon_loss + sparse_loss
    opt.zero_grad(); loss.backward(); opt.step()
    if epoch % 100 == 0:
        active_frac = (h.detach() > 0.1).float().mean().item()
        print(f'Epoch {epoch}: recon={recon_loss:.4f}, active={active_frac:.1%}')

with torch.no_grad():
    _, h = model(X_t)
    print(f'Average active units: {(h > 0.1).float().mean():.1%}')
```

## Contractive Autoencoder

A contractive autoencoder (CAE) penalises the Frobenius norm of the encoder Jacobian ‖∂h/∂x‖_F². This forces the encoder to be insensitive to small perturbations of the input — the latent code changes slowly as x moves slightly. For a sigmoid encoder, the Jacobian penalty simplifies to Σⱼ h_j²(1-h_j)² Σᵢ W_ji², which is cheap to compute analytically.

```python
import numpy as np
import torch
import torch.nn as nn
from sklearn.datasets import load_digits
from sklearn.preprocessing import MinMaxScaler

X, y = load_digits(return_X_y=True)
X = MinMaxScaler().fit_transform(X).astype(np.float32)
X_t = torch.tensor(X)
d_in, d_h = 64, 32

class ContractiveAE(nn.Module):
    def __init__(self):
        super().__init__()
        self.enc_layer = nn.Linear(d_in, d_h)
        self.dec = nn.Sequential(nn.Linear(d_h, d_in), nn.Sigmoid())
    def forward(self, x):
        h = torch.sigmoid(self.enc_layer(x))
        return self.dec(h), h

def jacobian_frob(h, W):
    # Analytic Frobenius norm for sigmoid encoder
    s = h * (1.0 - h)               # (n, d_h) — sigmoid derivative
    return (s**2 @ (W**2).sum(dim=1)).mean()

model = ContractiveAE()
opt = torch.optim.Adam(model.parameters(), lr=1e-3)
lambda_c = 1e-4

for epoch in range(300):
    x_recon, h = model(X_t)
    recon = nn.MSELoss()(x_recon, X_t)
    contract = lambda_c * jacobian_frob(h, model.enc_layer.weight)
    loss = recon + contract
    opt.zero_grad(); loss.backward(); opt.step()
    if epoch % 100 == 0:
        print(f'Epoch {epoch}: recon={recon:.4f}, contract={contract:.6f}')
print('Training complete')
```

## Linear AE = PCA, and VAE Preview

A linear autoencoder with MSE loss (no nonlinearities) spans the same subspace as PCA: the learned encoder directions are the top k eigenvectors of XᵀX. They may be rotated relative to the true PCs, but the subspace is identical. The VAE (Variational Autoencoder) extends this framework probabilistically: the encoder outputs a distribution q(z|x) = N(μ(x), σ²(x)) and the loss adds a KL term to enforce a smooth, continuous latent space — enabling generation.

- Undercomplete AE: compression via bottleneck; equivalent to PCA when linear
- Denoising AE: corruption + reconstruction; learns data manifold and score function
- Sparse AE: overcomplete + L1 or KL penalty; disentangled, interpretable features
- Contractive AE: Jacobian penalty; stable latent code invariant to perturbations
- VAE: probabilistic encoder; continuous, generative latent space

| Variant | Regularisation | Latent Structure | Best For |
| --- | --- | --- | --- |
| Undercomplete | Bottleneck size | Compact, dense | Dimensionality reduction |
| Denoising | Input corruption | Manifold-aligned | Robust features, image restoration |
| Sparse | L1 or KL on activations | Sparse, overcomplete | Interpretable features, dictionary learning |
| Contractive | Jacobian Frobenius | Smooth, stable | Noise-robust representations |
| VAE | KL(q(z|x)||p(z)) | Continuous, generative | Generation, interpolation |

All autoencoder variants share the encoder-decoder skeleton but differ in what they regularise. The choice of regularisation determines the geometry of the latent space: a bottleneck produces a compact subspace (like PCA), corruption pressure produces a manifold-aligned code, L1 penalty produces a sparse dictionary, and Jacobian penalty produces a flat, locally-linear mapping. Each regularisation strategy is suited to a different downstream goal.

---

> **Choosing an Autoencoder Variant**: For dimensionality reduction comparable to PCA: undercomplete AE. For learning representations that generalise under noise: denoising AE. For human-interpretable features: sparse AE. For smooth latent spaces needed for interpolation or generation: VAE. For production feature extractors that are stable under input perturbations: contractive AE.

