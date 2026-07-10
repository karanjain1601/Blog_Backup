---
title: "Variational Autoencoders: Continuous Latent Space and ELBO"
slug: "vae-continuous-latent"
description: ""
tags: ["vae", "generative-models", "elbo", "latent-space", "computer-vision"]
topic: ""
status: ""
updated: ""
blocks_json: "[{"type":"h2","content":"Overview"},{"type":"text","content":"Variational Autoencoders (VAEs) combine a probabilistic encoder q(z|x) with a generative decoder p(x|z) trained jointly via a principled variational lower bound. Unlike plain autoencoders, VAEs impose a prior p(z) = N(0, I) on the latent space, forcing it to be smooth and continuous—enabling generation by sampling z directly."},{"type":"text","content":"VAEs are theoretically grounded in variational inference and offer explicit likelihood estimation, stable training, and natural support for disentanglement extensions like β-VAE. They trade off sample sharpness for a structured latent space, making them complementary to GANs for controlled generative modeling."},{"type":"h2","content":"ELBO Derivation"},{"type":"text","content":"Maximizing log p(x) directly is intractable because it requires integrating over all z. Instead, we maximize the Evidence Lower BOund (ELBO): log p(x) ≥ E_q[log p(x|z)] - KL(q(z|x) || p(z)). The first term is reconstruction likelihood; the second is a regularization term pulling q toward the prior."},{"type":"text","content":"The KL divergence KL(N(μ, σ²) || N(0, I)) has a closed form: -0.5 * Σ(1 + log σ² - μ² - σ²). This means we never need to sample to compute the regularization term—only the reconstruction term requires sampling through the reparameterization trick."},{"type":"h2","content":"Reparameterization Trick"},{"type":"text","content":"Sampling z ~ q(z|x) = N(μ, σ²) is non-differentiable, blocking gradient flow to the encoder. The reparameterization trick rewrites z = μ + ε * σ where ε ~ N(0, I). Now gradients flow through μ and σ (encoder outputs) while ε is treated as a fixed random variable, enabling end-to-end backpropagation."},{"type":"code","lang":"python","content":"import torch\nimport torch.nn as nn\n\nclass VAEEncoder(nn.Module):\n    def __init__(self, in_ch=3, latent_dim=128):\n        super().__init__()\n        self.conv = nn.Sequential(\n            nn.Conv2d(in_ch, 32, 4, 2, 1), nn.ReLU(),\n            nn.Conv2d(32, 64, 4, 2, 1),   nn.ReLU(),\n            nn.Conv2d(64, 128, 4, 2, 1),  nn.ReLU(),\n        )\n        self.fc_mu  = nn.Linear(128 * 4 * 4, latent_dim)\n        self.fc_lv  = nn.Linear(128 * 4 * 4, latent_dim)\n    def forward(self, x):\n        h = self.conv(x).flatten(1)\n        mu, lv = self.fc_mu(h), self.fc_lv(h)\n        z = mu + torch.randn_like(mu) * (0.5 * lv).exp()\n        return z, mu, lv"},{"type":"h2","content":"Decoder and Reconstruction"},{"type":"text","content":"The decoder p(x|z) maps a latent vector back to pixel space. For binary or normalized images, a Bernoulli decoder with binary cross-entropy reconstruction loss is common. For continuous image values, a Gaussian decoder with MSE loss is used. The choice affects the tradeoff between sharpness and blurriness."},{"type":"code","lang":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef kl_loss(mu, log_var):\n    \"\"\"Analytical KL divergence from N(mu, sigma^2) to N(0,I).\"\"\"\n    return -0.5 * torch.sum(\n        1 + log_var - mu.pow(2) - log_var.exp()\n    ) / mu.size(0)   # mean over batch"},{"type":"code","lang":"python","content":"import torch.nn.functional as F\n\ndef vae_loss(x_hat, x, mu, log_var, beta=1.0):\n    \"\"\"Full VAE ELBO loss: reconstruction + beta * KL.\n    x_hat, x: (B, C, H, W) — predicted and target images in [0, 1]\n    beta: 1.0 for standard VAE, \u003e1 for beta-VAE\n    \"\"\"\n    recon = F.binary_cross_entropy(\n        x_hat, x, reduction=\u0027sum\u0027\n    ) / x.size(0)\n    kl = -0.5 * torch.sum(\n        1 + log_var - mu.pow(2) - log_var.exp()\n    ) / x.size(0)\n    return recon + beta * kl, recon, kl"},{"type":"text","content":"VAE decoders tend to produce blurry images because the Gaussian or Bernoulli assumptions encourage averaging over possible reconstructions. This blurriness is the main quality gap relative to GANs. Hierarchical VAEs (VDVAE, NVAE) and VQ-VAE address this with stronger decoders and discrete latent spaces respectively."},{"type":"h2","content":"β-VAE and Disentanglement"},{"type":"text","content":"β-VAE multiplies the KL term by β \u003e 1, applying stronger pressure for the posterior q(z|x) to match the isotropic Gaussian prior. This encourages each latent dimension to encode exactly one independent generative factor (pose, lighting, color) at the cost of lower reconstruction fidelity."},{"type":"callout","variant":"tip","content":"The β coefficient in β-VAE trades off reconstruction fidelity against latent disentanglement. β=1 is standard VAE. β=4–10 encourages each latent dimension to encode one independent factor — useful for controllable generation."},{"type":"code","lang":"python","content":"import torch\nimport numpy as np\n\n@torch.no_grad()\ndef latent_traversal(decoder, z_base, dim, lo=-3.0, hi=3.0, steps=10, device=\u0027cuda\u0027):\n    \"\"\"Sweep one latent dimension while holding others fixed.\n    Returns a tensor of shape (steps, C, H, W) for visualization.\n    \"\"\"\n    vals = torch.linspace(lo, hi, steps, device=device)\n    imgs = []\n    for v in vals:\n        z = z_base.clone().to(device)   # (1, latent_dim)\n        z[0, dim] = v\n        imgs.append(decoder(z))          # (1, C, H, W)\n    return torch.cat(imgs, dim=0)        # (steps, C, H, W)"},{"type":"table","headers":["Model","β Value","Reconstruction Quality","Disentanglement","FID"],"rows":[["VAE","1","High","Low","~60"],["β-VAE","4","Medium-High","Medium","~75"],["β-VAE","10","Medium","High","~90"],["VQ-VAE","N/A","High","Medium","~45"],["VQ-VAE-2","N/A","Very High","Medium","~31"]]},{"type":"h2","content":"Key Takeaways"},{"type":"text","content":"The ELBO provides a principled objective with two competing forces: reconstruction fidelity (likelihood term) and regularization toward the prior (KL term). The reparameterization trick is the key insight that makes gradient-based training possible despite stochastic sampling in the forward pass."},{"type":"text","content":"β-VAE demonstrates that simple coefficient scaling meaningfully changes the inductive bias of the model toward disentanglement. When controllable generation is the goal (e.g., varying only one attribute), start with β=4 and sweep upward, monitoring both FID and a disentanglement metric like MIG or DCI."},{"type":"text","content":"VQ-VAE and VQ-VAE-2 bypass the blurriness problem by quantizing the latent space into a learned discrete codebook, then training an autoregressive prior over codebook indices. This combination of VAE compression with AR modeling produces sharp, high-resolution images and underpins models like DALL-E and RQ-VAE-Transformer."}]"
---
# Variational Autoencoders: Continuous Latent Space and ELBO

Variational Autoencoders (VAEs) combine a probabilistic encoder q(z|x) with a generative decoder p(x|z) trained jointly via a principled variational lower bound. Unlike plain autoencoders, VAEs impose a prior p(z) = N(0, I) on the latent space, forcing it to be smooth and continuous—enabling generation by sampling z directly.

VAEs are theoretically grounded in variational inference and offer explicit likelihood estimation, stable training, and natural support for disentanglement extensions like β-VAE. They trade off sample sharpness for a structured latent space, making them complementary to GANs for controlled generative modeling.

Maximizing log p(x) directly is intractable because it requires integrating over all z. Instead, we maximize the Evidence Lower BOund (ELBO): log p(x) ≥ E_q[log p(x|z)] - KL(q(z|x) || p(z)). The first term is reconstruction likelihood; the second is a regularization term pulling q toward the prior.

The KL divergence KL(N(μ, σ²) || N(0, I)) has a closed form: -0.5 * Σ(1 + log σ² - μ² - σ²). This means we never need to sample to compute the regularization term—only the reconstruction term requires sampling through the reparameterization trick.

Sampling z ~ q(z|x) = N(μ, σ²) is non-differentiable, blocking gradient flow to the encoder. The reparameterization trick rewrites z = μ + ε * σ where ε ~ N(0, I). Now gradients flow through μ and σ (encoder outputs) while ε is treated as a fixed random variable, enabling end-to-end backpropagation.

```
import torch
import torch.nn as nn

class VAEEncoder(nn.Module):
    def __init__(self, in_ch=3, latent_dim=128):
        super().__init__()
        self.conv = nn.Sequential(
            nn.Conv2d(in_ch, 32, 4, 2, 1), nn.ReLU(),
            nn.Conv2d(32, 64, 4, 2, 1),   nn.ReLU(),
            nn.Conv2d(64, 128, 4, 2, 1),  nn.ReLU(),
        )
        self.fc_mu  = nn.Linear(128 * 4 * 4, latent_dim)
        self.fc_lv  = nn.Linear(128 * 4 * 4, latent_dim)
    def forward(self, x):
        h = self.conv(x).flatten(1)
        mu, lv = self.fc_mu(h), self.fc_lv(h)
        z = mu + torch.randn_like(mu) * (0.5 * lv).exp()
        return z, mu, lv
```

The decoder p(x|z) maps a latent vector back to pixel space. For binary or normalized images, a Bernoulli decoder with binary cross-entropy reconstruction loss is common. For continuous image values, a Gaussian decoder with MSE loss is used. The choice affects the tradeoff between sharpness and blurriness.

```
import torch
import torch.nn.functional as F

def kl_loss(mu, log_var):
    """Analytical KL divergence from N(mu, sigma^2) to N(0,I)."""
    return -0.5 * torch.sum(
        1 + log_var - mu.pow(2) - log_var.exp()
    ) / mu.size(0)   # mean over batch
```

```
import torch.nn.functional as F

def vae_loss(x_hat, x, mu, log_var, beta=1.0):
    """Full VAE ELBO loss: reconstruction + beta * KL.
    x_hat, x: (B, C, H, W) — predicted and target images in [0, 1]
    beta: 1.0 for standard VAE, >1 for beta-VAE
    """
    recon = F.binary_cross_entropy(
        x_hat, x, reduction='sum'
    ) / x.size(0)
    kl = -0.5 * torch.sum(
        1 + log_var - mu.pow(2) - log_var.exp()
    ) / x.size(0)
    return recon + beta * kl, recon, kl
```

VAE decoders tend to produce blurry images because the Gaussian or Bernoulli assumptions encourage averaging over possible reconstructions. This blurriness is the main quality gap relative to GANs. Hierarchical VAEs (VDVAE, NVAE) and VQ-VAE address this with stronger decoders and discrete latent spaces respectively.

β-VAE multiplies the KL term by β > 1, applying stronger pressure for the posterior q(z|x) to match the isotropic Gaussian prior. This encourages each latent dimension to encode exactly one independent generative factor (pose, lighting, color) at the cost of lower reconstruction fidelity.

> **tip**: The β coefficient in β-VAE trades off reconstruction fidelity against latent disentanglement. β=1 is standard VAE. β=4–10 encourages each latent dimension to encode one independent factor — useful for controllable generation.

```
import torch
import numpy as np

@torch.no_grad()
def latent_traversal(decoder, z_base, dim, lo=-3.0, hi=3.0, steps=10, device='cuda'):
    """Sweep one latent dimension while holding others fixed.
    Returns a tensor of shape (steps, C, H, W) for visualization.
    """
    vals = torch.linspace(lo, hi, steps, device=device)
    imgs = []
    for v in vals:
        z = z_base.clone().to(device)   # (1, latent_dim)
        z[0, dim] = v
        imgs.append(decoder(z))          # (1, C, H, W)
    return torch.cat(imgs, dim=0)        # (steps, C, H, W)
```

| Model | β Value | Reconstruction Quality | Disentanglement | FID |
| --- | --- | --- | --- | --- |
| VAE | 1 | High | Low | ~60 |
| β-VAE | 4 | Medium-High | Medium | ~75 |
| β-VAE | 10 | Medium | High | ~90 |
| VQ-VAE | N/A | High | Medium | ~45 |
| VQ-VAE-2 | N/A | Very High | Medium | ~31 |

The ELBO provides a principled objective with two competing forces: reconstruction fidelity (likelihood term) and regularization toward the prior (KL term). The reparameterization trick is the key insight that makes gradient-based training possible despite stochastic sampling in the forward pass.

β-VAE demonstrates that simple coefficient scaling meaningfully changes the inductive bias of the model toward disentanglement. When controllable generation is the goal (e.g., varying only one attribute), start with β=4 and sweep upward, monitoring both FID and a disentanglement metric like MIG or DCI.

VQ-VAE and VQ-VAE-2 bypass the blurriness problem by quantizing the latent space into a learned discrete codebook, then training an autoregressive prior over codebook indices. This combination of VAE compression with AR modeling produces sharp, high-resolution images and underpins models like DALL-E and RQ-VAE-Transformer.

