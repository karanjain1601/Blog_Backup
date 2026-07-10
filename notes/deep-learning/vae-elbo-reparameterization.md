---
title: "VAE — ELBO Derivation and Reparameterization Trick"
slug: "vae-elbo-reparameterization"
description: "A rigorous derivation of the VAE objective from first principles: how the intractable marginal log p(x) is lower-bounded by the ELBO, why the reparameterization trick enables gradients through stochastic nodes, and how posterior collapse arises and is fixed with cyclical KL annealing."
tags: ["deep-learning", "generative-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Variational Autoencoders (Kingma \u0026 Welling 2013) are latent variable models that jointly learn to compress data into a continuous latent space and generate data from that space. The generative model is p(x,z) = p(x|z)p(z) where p(z) = N(0,I) is the prior and p_θ(x|z) is a learned decoder. The inference model q_φ(z|x) approximates the intractable posterior p(z|x). Training maximizes a lower bound on log p(x) called the ELBO, derived by introducing q and applying Jensen\u0027s inequality. The reparameterization trick converts the stochastic sampling step into a differentiable operation, allowing gradient-based optimization of both the encoder φ and decoder θ simultaneously."},{"type":"heading","level":2,"content":"ELBO Derivation"},{"type":"text","content":"Starting from log p(x) and introducing q_φ(z|x) via importance weighting: log p(x) = log ∫ p(x|z)p(z) dz = log E_{q_φ}[p(x|z)p(z)/q_φ(z|x)] ≥ E_{q_φ}[log p(x|z)] + E_{q_φ}[log p(z)/q_φ(z|x)] = E_{q_φ}[log p(x|z)] - KL(q_φ(z|x) || p(z)). The gap between log p(x) and the ELBO is KL(q_φ(z|x) || p(z|x)) ≥ 0, so ELBO ≤ log p(x). Maximizing the ELBO simultaneously maximizes a lower bound on the marginal likelihood and minimizes the KL divergence between the variational posterior and the true posterior."},{"type":"heading","level":2,"content":"Reparameterization Trick"},{"type":"text","content":"The ELBO requires computing gradients through E_{q_φ}[log p(x|z)], but z ~ q_φ(z|x) = N(μ_φ(x), σ_φ²(x)) is a stochastic node — naively, gradients cannot flow through the sampling operation. The reparameterization trick factors z = μ_φ(x) + σ_φ(x) ⊙ ε where ε ~ N(0,I). Now z is a deterministic function of the parameters μ_φ, σ_φ and the auxiliary noise ε. Gradients of the loss with respect to φ flow through z = μ + σ·ε cleanly via backpropagation. The encoder outputs μ (mean) and log σ² (log variance) for numerical stability, and σ = exp(0.5 · log σ²)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nfrom torch.utils.data import DataLoader\nfrom torchvision import datasets, transforms\n\nclass VAEEncoder(nn.Module):\n    def __init__(self, input_dim=784, hidden_dim=512, latent_dim=20):\n        super().__init__()\n        self.fc1 = nn.Linear(input_dim, hidden_dim)\n        self.fc_mu  = nn.Linear(hidden_dim, latent_dim)\n        self.fc_logvar = nn.Linear(hidden_dim, latent_dim)\n\n    def forward(self, x):\n        h = F.relu(self.fc1(x.view(x.size(0), -1)))\n        return self.fc_mu(h), self.fc_logvar(h)\n\nclass VAEDecoder(nn.Module):\n    def __init__(self, latent_dim=20, hidden_dim=512, output_dim=784):\n        super().__init__()\n        self.fc1 = nn.Linear(latent_dim, hidden_dim)\n        self.fc2 = nn.Linear(hidden_dim, output_dim)\n\n    def forward(self, z):\n        h = F.relu(self.fc1(z))\n        return torch.sigmoid(self.fc2(h))\n\nclass VAE(nn.Module):\n    def __init__(self, latent_dim=20):\n        super().__init__()\n        self.encoder = VAEEncoder(latent_dim=latent_dim)\n        self.decoder = VAEDecoder(latent_dim=latent_dim)\n\n    def reparameterize(self, mu, logvar):\n        \"\"\"z = mu + std * eps; eps ~ N(0, I) — differentiable sampling.\"\"\"\n        std = torch.exp(0.5 * logvar)\n        eps = torch.randn_like(std)\n        return mu + std * eps\n\n    def forward(self, x):\n        mu, logvar = self.encoder(x)\n        z = self.reparameterize(mu, logvar)\n        recon = self.decoder(z)\n        return recon, mu, logvar\n\nmodel = VAE(latent_dim=2)\nx = torch.randn(8, 1, 28, 28)\nrecon, mu, logvar = model(x)\nprint(f\u0027Encoder mu: {mu.shape}, logvar: {logvar.shape}\u0027)\nprint(f\u0027Decoder recon: {recon.shape}\u0027)"},{"type":"heading","level":2,"content":"ELBO Loss — Reconstruction and KL Terms"},{"type":"text","content":"The ELBO has two terms. The reconstruction term E_{q_φ}[log p_θ(x|z)] measures how well the decoder recovers x from z. For a Bernoulli decoder (binary images), this is binary cross-entropy; for a Gaussian decoder, it is mean squared error. The KL term -KL(q_φ(z|x) || p(z)) regularizes the posterior toward the prior N(0,I). For diagonal Gaussian encoder and standard Gaussian prior, the KL has a closed form: KL = -½ Σⱼ (1 + log σⱼ² - μⱼ² - σⱼ²). The closed form avoids Monte Carlo estimation of the KL, reducing gradient variance and making training more stable."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef vae_loss(recon, x, mu, logvar, beta=1.0):\n    \"\"\"\n    ELBO loss = reconstruction_loss + beta * KL_divergence.\n    recon: (B, 784) sigmoid outputs.\n    x:     (B, 1, 28, 28) input images in [0, 1].\n    mu, logvar: (B, latent_dim) encoder outputs.\n    KL closed form: -0.5 * sum(1 + logvar - mu^2 - exp(logvar)).\n    \"\"\"\n    x_flat = x.view(x.size(0), -1)\n    # Bernoulli reconstruction: binary cross-entropy summed over pixels\n    recon_loss = F.binary_cross_entropy(recon, x_flat, reduction=\u0027sum\u0027) / x.size(0)\n    # KL divergence: analytical for q=N(mu, diag(sigma^2)) and p=N(0,I)\n    kl = -0.5 * torch.sum(1 + logvar - mu.pow(2) - logvar.exp(), dim=1)\n    kl_loss = kl.mean()\n    total = recon_loss + beta * kl_loss\n    return total, recon_loss.item(), kl_loss.item()\n\n# Sanity check at init: KL of N(0,I) vs N(0,I) should be 0\nmu_zero    = torch.zeros(16, 20)\nlogvar_zero = torch.zeros(16, 20)\nrecon_dummy = torch.rand(16, 784)\nx_dummy = torch.rand(16, 1, 28, 28)\ntotal, recon_l, kl_l = vae_loss(recon_dummy, x_dummy, mu_zero, logvar_zero)\nprint(f\u0027At init (mu=0, logvar=0): KL={kl_l:.4f} (expected ~0.0)\u0027)\nprint(f\u0027Total ELBO loss: {total:.4f}  | Recon: {recon_l:.4f}  | KL: {kl_l:.4f}\u0027)"},{"type":"heading","level":2,"content":"Gaussian vs Bernoulli Decoder Choice"},{"type":"text","content":"The decoder output distribution determines the form of the reconstruction term. A Bernoulli decoder (sigmoid output, BCE loss) is standard for binarized MNIST: each pixel is treated as an independent Bernoulli variable. A Gaussian decoder (linear output, MSE loss) is more appropriate for continuous images; the reconstruction term becomes E_{q}[-||x - μ_θ(z)||²/(2σ²)], where the decoder variance σ² can be fixed at 1 (equivalent to MSE) or learned. A learned σ² allows the model to adapt its reconstruction confidence per region. For natural images, a Laplace decoder (MAE loss, more robust to outliers) or a discretized logistic mixture (PixelCNN++ style) can improve sample sharpness over plain Gaussian decoders."},{"type":"list","ordered":false,"items":["Bernoulli decoder: sigmoid output + BCE loss — standard for binarized MNIST, assumes independent pixels.","Gaussian decoder: linear output + MSE — appropriate for continuous images; equivalent to maximizing N(x; μ_θ(z), I).","Discretized logistic decoder: more expressive output, used in PixelCNN++ and VQ-VAE to improve sharpness.","Fixed decoder variance σ²=1 simplifies training; learned σ² helps the model weight reconstruction confidence.","The choice of decoder distribution changes the scale of the reconstruction term relative to KL — affects effective β."]},{"type":"heading","level":2,"content":"Visualizing the 2D Latent Space"},{"type":"text","content":"A 2-dimensional latent space allows direct visualization of the learned representation. After training, encoding the MNIST test set and plotting the (μ₁, μ₂) values colored by digit class reveals cluster structure. Traversing the latent space by decoding points on a grid shows smooth interpolation between digit styles. This confirms that the VAE has organized the latent space semantically and that the decoder can generate coherent images from any point in the continuous prior."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nimport matplotlib\nmatplotlib.use(\u0027Agg\u0027)\nimport matplotlib.pyplot as plt\nfrom torchvision import datasets, transforms\n\ndef visualize_latent_space(model, device=\u0027cpu\u0027, n_samples=2000):\n    \"\"\"Plot 2D latent space of VAE trained on MNIST, colored by digit class.\"\"\"\n    model.eval()\n    transform = transforms.Compose([transforms.ToTensor()])\n    dataset = datasets.MNIST(root=\u0027/tmp/mnist\u0027, train=False, download=True, transform=transform)\n    loader = torch.utils.data.DataLoader(dataset, batch_size=256, shuffle=False)\n    zs, labels = [], []\n    with torch.no_grad():\n        for x, y in loader:\n            mu, _ = model.encoder(x.to(device))\n            zs.append(mu.cpu().numpy())\n            labels.append(y.numpy())\n            if sum(len(l) for l in labels) \u003e= n_samples:\n                break\n    zs = np.concatenate(zs)[:n_samples]\n    labels = np.concatenate(labels)[:n_samples]\n    fig, ax = plt.subplots(figsize=(7, 6))\n    scatter = ax.scatter(zs[:, 0], zs[:, 1], c=labels, cmap=\u0027tab10\u0027, alpha=0.6, s=6)\n    plt.colorbar(scatter, ax=ax, label=\u0027Digit class\u0027)\n    ax.set_xlabel(\u0027z₁\u0027); ax.set_ylabel(\u0027z₂\u0027); ax.set_title(\u0027VAE 2D Latent Space — MNIST\u0027)\n    plt.tight_layout(); plt.savefig(\u0027/tmp/vae_latent.png\u0027, dpi=120)\n    print(\u0027Saved latent space plot to /tmp/vae_latent.png\u0027)\n    return zs, labels\n\nfrom torch import nn\nclass MinimalVAE(nn.Module):\n    def __init__(self):\n        super().__init__()\n        self.encoder = nn.Sequential(nn.Flatten(), nn.Linear(784,256), nn.ReLU())\n        self.fc_mu = nn.Linear(256, 2)\n        self.fc_logvar = nn.Linear(256, 2)\n        self.decoder = nn.Sequential(nn.Linear(2,256), nn.ReLU(), nn.Linear(256,784), nn.Sigmoid())\n    def reparameterize(self, mu, logvar):\n        return mu + torch.exp(0.5 * logvar) * torch.randn_like(mu)\n    def forward(self, x):\n        h = self.encoder(x)\n        mu, logvar = self.fc_mu(h), self.fc_logvar(h)\n        return self.decoder(self.reparameterize(mu, logvar)), mu, logvar\nprint(\u00272D VAE ready for visualization\u0027)"},{"type":"heading","level":2,"content":"Posterior Collapse and Cyclical KL Annealing"},{"type":"text","content":"Posterior collapse occurs when the decoder becomes so powerful that it ignores the latent code z entirely. The encoder outputs q_φ(z|x) ≈ p(z) = N(0,I) for all x, driving KL → 0 while the reconstruction loss stagnates. This is especially common with autoregressive decoders (RNN, Transformer) that can model p(x) without z. The free bits heuristic sets a minimum KL per dimension λ (typically 2–4 bits), and β-VAE increases the KL weight. Cyclical KL annealing (Fu et al. 2019) schedules the KL weight as a sawtooth that rises from 0 to 1 multiple times per training run, periodically resetting the encoder to explore different latent uses before the decoder adapts."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef cyclical_kl_weight(step, n_cycles=4, ratio=0.5, max_steps=10000):\n    \"\"\"Sawtooth KL weight schedule: rise from 0 to 1 n_cycles times over training.\"\"\"\n    cycle_len = max_steps // n_cycles\n    cycle_pos = step % cycle_len\n    ramp_end  = int(cycle_len * ratio)\n    if cycle_pos \u003c ramp_end:\n        return cycle_pos / ramp_end\n    return 1.0\n\ndef free_bits_kl(kl_per_dim, lambda_fb=3.0):\n    \"\"\"Free bits: clamp per-dimension KL below lambda_fb to prevent collapse.\"\"\"\n    return torch.clamp(kl_per_dim, min=lambda_fb).sum(dim=-1).mean()\n\ndef detect_posterior_collapse(mu, logvar, threshold=0.05):\n    \"\"\"Flag latent dims where KL contribution is below threshold (collapsed).\"\"\"\n    kl_per_dim = -0.5 * (1 + logvar - mu.pow(2) - logvar.exp())\n    avg_kl = kl_per_dim.mean(dim=0)\n    collapsed = (avg_kl \u003c threshold).sum().item()\n    active    = (avg_kl \u003e= threshold).sum().item()\n    return avg_kl, collapsed, active\n\n# Simulate collapse scenario\ntorch.manual_seed(42)\nmu_collapsed    = torch.randn(64, 20) * 0.01\nlogvar_collapsed = torch.zeros(64, 20)\navg_kl, n_collapsed, n_active = detect_posterior_collapse(mu_collapsed, logvar_collapsed)\nprint(f\u0027Posterior collapse: {n_collapsed}/20 dims collapsed, {n_active} active\u0027)\nfor step in [0, 500, 1000, 2500, 3000]:\n    w = cyclical_kl_weight(step, n_cycles=4, max_steps=4000)\n    print(f\u0027  Step {step:4d}: cyclical KL weight = {w:.3f}\u0027)"},{"type":"callout","variant":"warning","title":"Posterior Collapse Warning","content":"If the KL term drops to near zero after the first few hundred steps and reconstruction loss plateaus, the decoder is ignoring the latent space. Diagnose by monitoring per-dimension KL; any dimension below 0.1 nats is effectively collapsed. Immediate fixes: reduce decoder capacity, add free bits (λ=2–4), or switch to cyclical KL annealing."},{"type":"table","headers":["ELBO Term","Mathematical Form","Role","Collapse Fix","β-VAE Adjustment"],"rows":[["Reconstruction","E_{q}[log p_θ(x|z)]","Measures how well decoder recovers x","Reduce decoder capacity","Unchanged (β only scales KL)"],["KL Divergence","-KL(q_φ(z|x) || p(z))","Regularizes posterior toward prior N(0,I)","Free bits: clamp KL ≥ λ per dim","Scaled by β: β·KL term"],["ELBO Gap","KL(q_φ(z|x) || p(z|x))","Tightness of bound (unobservable)","Better q capacity narrows gap","Larger β widens gap intentionally"],["β\u003e1 Pressure","Trades recon for disentanglement","Encourages independent latent dims","Cyclical annealing: β rises 0→1 repeatedly","Core mechanism of β-VAE"],["Free Bits λ","max(KL_d, λ) per dimension","Ensures each dim encodes ≥λ nats","Prevents KL→0 collapse","Combined with β for best results"]]},{"type":"list","ordered":false,"items":["The reparameterization trick works because z = μ + σ·ε separates the randomness (ε) from the parameters (μ, σ), enabling backprop through z.","For diagonal Gaussian q and standard Gaussian p, the KL has the closed form: -½ Σ(1 + log σ² - μ² - σ²).","Bernoulli decoder uses BCE loss; Gaussian decoder uses MSE loss — the choice changes the scale of the reconstruction term.","Posterior collapse is most common with autoregressive decoders (LSTM, Transformer) that are expressive enough to model p(x) without z.","Cyclical annealing outperforms monotonic annealing because each cycle resets the encoder to explore new latent uses."]},{"type":"divider"},{"type":"text","content":"The VAE framework provides a principled probabilistic generative model with a tractable training objective. Understanding the ELBO derivation clarifies why the reconstruction-KL tradeoff exists and what each term optimizes. The reparameterization trick is the core technical insight enabling end-to-end gradient flow. Posterior collapse remains the main failure mode to monitor in practice, with cyclical annealing and free bits as the most reliable remedies."}]"
---
# VAE — ELBO Derivation and Reparameterization Trick

Variational Autoencoders (Kingma & Welling 2013) are latent variable models that jointly learn to compress data into a continuous latent space and generate data from that space. The generative model is p(x,z) = p(x|z)p(z) where p(z) = N(0,I) is the prior and p_θ(x|z) is a learned decoder. The inference model q_φ(z|x) approximates the intractable posterior p(z|x). Training maximizes a lower bound on log p(x) called the ELBO, derived by introducing q and applying Jensen's inequality. The reparameterization trick converts the stochastic sampling step into a differentiable operation, allowing gradient-based optimization of both the encoder φ and decoder θ simultaneously.

## ELBO Derivation

Starting from log p(x) and introducing q_φ(z|x) via importance weighting: log p(x) = log ∫ p(x|z)p(z) dz = log E_{q_φ}[p(x|z)p(z)/q_φ(z|x)] ≥ E_{q_φ}[log p(x|z)] + E_{q_φ}[log p(z)/q_φ(z|x)] = E_{q_φ}[log p(x|z)] - KL(q_φ(z|x) || p(z)). The gap between log p(x) and the ELBO is KL(q_φ(z|x) || p(z|x)) ≥ 0, so ELBO ≤ log p(x). Maximizing the ELBO simultaneously maximizes a lower bound on the marginal likelihood and minimizes the KL divergence between the variational posterior and the true posterior.

## Reparameterization Trick

The ELBO requires computing gradients through E_{q_φ}[log p(x|z)], but z ~ q_φ(z|x) = N(μ_φ(x), σ_φ²(x)) is a stochastic node — naively, gradients cannot flow through the sampling operation. The reparameterization trick factors z = μ_φ(x) + σ_φ(x) ⊙ ε where ε ~ N(0,I). Now z is a deterministic function of the parameters μ_φ, σ_φ and the auxiliary noise ε. Gradients of the loss with respect to φ flow through z = μ + σ·ε cleanly via backpropagation. The encoder outputs μ (mean) and log σ² (log variance) for numerical stability, and σ = exp(0.5 · log σ²).

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
from torch.utils.data import DataLoader
from torchvision import datasets, transforms

class VAEEncoder(nn.Module):
    def __init__(self, input_dim=784, hidden_dim=512, latent_dim=20):
        super().__init__()
        self.fc1 = nn.Linear(input_dim, hidden_dim)
        self.fc_mu  = nn.Linear(hidden_dim, latent_dim)
        self.fc_logvar = nn.Linear(hidden_dim, latent_dim)

    def forward(self, x):
        h = F.relu(self.fc1(x.view(x.size(0), -1)))
        return self.fc_mu(h), self.fc_logvar(h)

class VAEDecoder(nn.Module):
    def __init__(self, latent_dim=20, hidden_dim=512, output_dim=784):
        super().__init__()
        self.fc1 = nn.Linear(latent_dim, hidden_dim)
        self.fc2 = nn.Linear(hidden_dim, output_dim)

    def forward(self, z):
        h = F.relu(self.fc1(z))
        return torch.sigmoid(self.fc2(h))

class VAE(nn.Module):
    def __init__(self, latent_dim=20):
        super().__init__()
        self.encoder = VAEEncoder(latent_dim=latent_dim)
        self.decoder = VAEDecoder(latent_dim=latent_dim)

    def reparameterize(self, mu, logvar):
        """z = mu + std * eps; eps ~ N(0, I) — differentiable sampling."""
        std = torch.exp(0.5 * logvar)
        eps = torch.randn_like(std)
        return mu + std * eps

    def forward(self, x):
        mu, logvar = self.encoder(x)
        z = self.reparameterize(mu, logvar)
        recon = self.decoder(z)
        return recon, mu, logvar

model = VAE(latent_dim=2)
x = torch.randn(8, 1, 28, 28)
recon, mu, logvar = model(x)
print(f'Encoder mu: {mu.shape}, logvar: {logvar.shape}')
print(f'Decoder recon: {recon.shape}')
```

## ELBO Loss — Reconstruction and KL Terms

The ELBO has two terms. The reconstruction term E_{q_φ}[log p_θ(x|z)] measures how well the decoder recovers x from z. For a Bernoulli decoder (binary images), this is binary cross-entropy; for a Gaussian decoder, it is mean squared error. The KL term -KL(q_φ(z|x) || p(z)) regularizes the posterior toward the prior N(0,I). For diagonal Gaussian encoder and standard Gaussian prior, the KL has a closed form: KL = -½ Σⱼ (1 + log σⱼ² - μⱼ² - σⱼ²). The closed form avoids Monte Carlo estimation of the KL, reducing gradient variance and making training more stable.

```python
import torch
import torch.nn.functional as F

def vae_loss(recon, x, mu, logvar, beta=1.0):
    """
    ELBO loss = reconstruction_loss + beta * KL_divergence.
    recon: (B, 784) sigmoid outputs.
    x:     (B, 1, 28, 28) input images in [0, 1].
    mu, logvar: (B, latent_dim) encoder outputs.
    KL closed form: -0.5 * sum(1 + logvar - mu^2 - exp(logvar)).
    """
    x_flat = x.view(x.size(0), -1)
    # Bernoulli reconstruction: binary cross-entropy summed over pixels
    recon_loss = F.binary_cross_entropy(recon, x_flat, reduction='sum') / x.size(0)
    # KL divergence: analytical for q=N(mu, diag(sigma^2)) and p=N(0,I)
    kl = -0.5 * torch.sum(1 + logvar - mu.pow(2) - logvar.exp(), dim=1)
    kl_loss = kl.mean()
    total = recon_loss + beta * kl_loss
    return total, recon_loss.item(), kl_loss.item()

# Sanity check at init: KL of N(0,I) vs N(0,I) should be 0
mu_zero    = torch.zeros(16, 20)
logvar_zero = torch.zeros(16, 20)
recon_dummy = torch.rand(16, 784)
x_dummy = torch.rand(16, 1, 28, 28)
total, recon_l, kl_l = vae_loss(recon_dummy, x_dummy, mu_zero, logvar_zero)
print(f'At init (mu=0, logvar=0): KL={kl_l:.4f} (expected ~0.0)')
print(f'Total ELBO loss: {total:.4f}  | Recon: {recon_l:.4f}  | KL: {kl_l:.4f}')
```

## Gaussian vs Bernoulli Decoder Choice

The decoder output distribution determines the form of the reconstruction term. A Bernoulli decoder (sigmoid output, BCE loss) is standard for binarized MNIST: each pixel is treated as an independent Bernoulli variable. A Gaussian decoder (linear output, MSE loss) is more appropriate for continuous images; the reconstruction term becomes E_{q}[-||x - μ_θ(z)||²/(2σ²)], where the decoder variance σ² can be fixed at 1 (equivalent to MSE) or learned. A learned σ² allows the model to adapt its reconstruction confidence per region. For natural images, a Laplace decoder (MAE loss, more robust to outliers) or a discretized logistic mixture (PixelCNN++ style) can improve sample sharpness over plain Gaussian decoders.

- Bernoulli decoder: sigmoid output + BCE loss — standard for binarized MNIST, assumes independent pixels.
- Gaussian decoder: linear output + MSE — appropriate for continuous images; equivalent to maximizing N(x; μ_θ(z), I).
- Discretized logistic decoder: more expressive output, used in PixelCNN++ and VQ-VAE to improve sharpness.
- Fixed decoder variance σ²=1 simplifies training; learned σ² helps the model weight reconstruction confidence.
- The choice of decoder distribution changes the scale of the reconstruction term relative to KL — affects effective β.

## Visualizing the 2D Latent Space

A 2-dimensional latent space allows direct visualization of the learned representation. After training, encoding the MNIST test set and plotting the (μ₁, μ₂) values colored by digit class reveals cluster structure. Traversing the latent space by decoding points on a grid shows smooth interpolation between digit styles. This confirms that the VAE has organized the latent space semantically and that the decoder can generate coherent images from any point in the continuous prior.

```python
import torch
import numpy as np
import matplotlib
matplotlib.use('Agg')
import matplotlib.pyplot as plt
from torchvision import datasets, transforms

def visualize_latent_space(model, device='cpu', n_samples=2000):
    """Plot 2D latent space of VAE trained on MNIST, colored by digit class."""
    model.eval()
    transform = transforms.Compose([transforms.ToTensor()])
    dataset = datasets.MNIST(root='/tmp/mnist', train=False, download=True, transform=transform)
    loader = torch.utils.data.DataLoader(dataset, batch_size=256, shuffle=False)
    zs, labels = [], []
    with torch.no_grad():
        for x, y in loader:
            mu, _ = model.encoder(x.to(device))
            zs.append(mu.cpu().numpy())
            labels.append(y.numpy())
            if sum(len(l) for l in labels) >= n_samples:
                break
    zs = np.concatenate(zs)[:n_samples]
    labels = np.concatenate(labels)[:n_samples]
    fig, ax = plt.subplots(figsize=(7, 6))
    scatter = ax.scatter(zs[:, 0], zs[:, 1], c=labels, cmap='tab10', alpha=0.6, s=6)
    plt.colorbar(scatter, ax=ax, label='Digit class')
    ax.set_xlabel('z₁'); ax.set_ylabel('z₂'); ax.set_title('VAE 2D Latent Space — MNIST')
    plt.tight_layout(); plt.savefig('/tmp/vae_latent.png', dpi=120)
    print('Saved latent space plot to /tmp/vae_latent.png')
    return zs, labels

from torch import nn
class MinimalVAE(nn.Module):
    def __init__(self):
        super().__init__()
        self.encoder = nn.Sequential(nn.Flatten(), nn.Linear(784,256), nn.ReLU())
        self.fc_mu = nn.Linear(256, 2)
        self.fc_logvar = nn.Linear(256, 2)
        self.decoder = nn.Sequential(nn.Linear(2,256), nn.ReLU(), nn.Linear(256,784), nn.Sigmoid())
    def reparameterize(self, mu, logvar):
        return mu + torch.exp(0.5 * logvar) * torch.randn_like(mu)
    def forward(self, x):
        h = self.encoder(x)
        mu, logvar = self.fc_mu(h), self.fc_logvar(h)
        return self.decoder(self.reparameterize(mu, logvar)), mu, logvar
print('2D VAE ready for visualization')
```

## Posterior Collapse and Cyclical KL Annealing

Posterior collapse occurs when the decoder becomes so powerful that it ignores the latent code z entirely. The encoder outputs q_φ(z|x) ≈ p(z) = N(0,I) for all x, driving KL → 0 while the reconstruction loss stagnates. This is especially common with autoregressive decoders (RNN, Transformer) that can model p(x) without z. The free bits heuristic sets a minimum KL per dimension λ (typically 2–4 bits), and β-VAE increases the KL weight. Cyclical KL annealing (Fu et al. 2019) schedules the KL weight as a sawtooth that rises from 0 to 1 multiple times per training run, periodically resetting the encoder to explore different latent uses before the decoder adapts.

```python
import torch
import torch.nn as nn
import numpy as np

def cyclical_kl_weight(step, n_cycles=4, ratio=0.5, max_steps=10000):
    """Sawtooth KL weight schedule: rise from 0 to 1 n_cycles times over training."""
    cycle_len = max_steps // n_cycles
    cycle_pos = step % cycle_len
    ramp_end  = int(cycle_len * ratio)
    if cycle_pos < ramp_end:
        return cycle_pos / ramp_end
    return 1.0

def free_bits_kl(kl_per_dim, lambda_fb=3.0):
    """Free bits: clamp per-dimension KL below lambda_fb to prevent collapse."""
    return torch.clamp(kl_per_dim, min=lambda_fb).sum(dim=-1).mean()

def detect_posterior_collapse(mu, logvar, threshold=0.05):
    """Flag latent dims where KL contribution is below threshold (collapsed)."""
    kl_per_dim = -0.5 * (1 + logvar - mu.pow(2) - logvar.exp())
    avg_kl = kl_per_dim.mean(dim=0)
    collapsed = (avg_kl < threshold).sum().item()
    active    = (avg_kl >= threshold).sum().item()
    return avg_kl, collapsed, active

# Simulate collapse scenario
torch.manual_seed(42)
mu_collapsed    = torch.randn(64, 20) * 0.01
logvar_collapsed = torch.zeros(64, 20)
avg_kl, n_collapsed, n_active = detect_posterior_collapse(mu_collapsed, logvar_collapsed)
print(f'Posterior collapse: {n_collapsed}/20 dims collapsed, {n_active} active')
for step in [0, 500, 1000, 2500, 3000]:
    w = cyclical_kl_weight(step, n_cycles=4, max_steps=4000)
    print(f'  Step {step:4d}: cyclical KL weight = {w:.3f}')
```

> **Posterior Collapse Warning**: If the KL term drops to near zero after the first few hundred steps and reconstruction loss plateaus, the decoder is ignoring the latent space. Diagnose by monitoring per-dimension KL; any dimension below 0.1 nats is effectively collapsed. Immediate fixes: reduce decoder capacity, add free bits (λ=2–4), or switch to cyclical KL annealing.

| ELBO Term | Mathematical Form | Role | Collapse Fix | β-VAE Adjustment |
| --- | --- | --- | --- | --- |
| Reconstruction | E_{q}[log p_θ(x|z)] | Measures how well decoder recovers x | Reduce decoder capacity | Unchanged (β only scales KL) |
| KL Divergence | -KL(q_φ(z|x) || p(z)) | Regularizes posterior toward prior N(0,I) | Free bits: clamp KL ≥ λ per dim | Scaled by β: β·KL term |
| ELBO Gap | KL(q_φ(z|x) || p(z|x)) | Tightness of bound (unobservable) | Better q capacity narrows gap | Larger β widens gap intentionally |
| β>1 Pressure | Trades recon for disentanglement | Encourages independent latent dims | Cyclical annealing: β rises 0→1 repeatedly | Core mechanism of β-VAE |
| Free Bits λ | max(KL_d, λ) per dimension | Ensures each dim encodes ≥λ nats | Prevents KL→0 collapse | Combined with β for best results |

- The reparameterization trick works because z = μ + σ·ε separates the randomness (ε) from the parameters (μ, σ), enabling backprop through z.
- For diagonal Gaussian q and standard Gaussian p, the KL has the closed form: -½ Σ(1 + log σ² - μ² - σ²).
- Bernoulli decoder uses BCE loss; Gaussian decoder uses MSE loss — the choice changes the scale of the reconstruction term.
- Posterior collapse is most common with autoregressive decoders (LSTM, Transformer) that are expressive enough to model p(x) without z.
- Cyclical annealing outperforms monotonic annealing because each cycle resets the encoder to explore new latent uses.

---

The VAE framework provides a principled probabilistic generative model with a tractable training objective. Understanding the ELBO derivation clarifies why the reconstruction-KL tradeoff exists and what each term optimizes. The reparameterization trick is the core technical insight enabling end-to-end gradient flow. Posterior collapse remains the main failure mode to monitor in practice, with cyclical annealing and free bits as the most reliable remedies.

