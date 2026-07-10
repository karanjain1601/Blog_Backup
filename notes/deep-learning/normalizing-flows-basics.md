---
title: "Normalizing Flows — Change of Variables and Exact Likelihood"
slug: "normalizing-flows-basics"
description: "Normalizing flows learn a bijective mapping f: X <-> Z where Z~N(0,I), enabling exact likelihood computation via the change of variables formula log p_X(x) = log p_Z(f(x)) + log|det J_f(x)|. Covers coupling layers, NICE, autoregressive flows, and the comparison with VAE, GAN, and diffusion."
tags: ["deep-learning", "generative-models", "gans", "normalizing-flows"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"A normalizing flow is a generative model that learns a bijective (invertible) function f: X ↔ Z, where Z follows a simple base distribution such as N(0,I). The name comes from the idea that the transformation \u0027normalises\u0027 the complex data distribution into a Gaussian. Flows offer a property unique among deep generative models: exact log-likelihood computation. Unlike VAEs (lower bound) and GANs (implicit distribution), flows give the exact log p(x) via the change of variables formula, enabling direct maximum likelihood training."},{"type":"heading","level":2,"content":"Change of Variables Formula"},{"type":"text","content":"If Z ~ p_Z and x = f⁻¹(z) where f is bijective, then the density of X satisfies: p_X(x) = p_Z(f(x)) |det J_f(x)|. Taking logs: log p_X(x) = log p_Z(f(x)) + log|det J_f(x)|. The first term is the log-likelihood under the simple base distribution. The second term is the log absolute Jacobian determinant of f — it accounts for how f stretches or compresses volume. Training maximises E_x[log p_X(x)] over the dataset. The challenge: for a general neural network, computing det J_f costs O(d³) for a d-dimensional input — prohibitive for images."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef change_of_variables_demo():\n    \u0027\u0027\u00271D: Z ~ N(0,1), x = f^{-1}(z) = z^3. Verify p_X integrates to 1.\u0027\u0027\u0027\n    z = torch.linspace(-2.5, 2.5, 1000)\n    x = z ** 3              # forward map: z -\u003e x\n    # Change of variables: p_X(x) = p_Z(z) / |df/dz|\n    # df/dz = 3z^2, so p_X = p_Z(z) / (3z^2)\n    pz  = torch.exp(-0.5 * z**2) / (2 * torch.pi) ** 0.5\n    jac = (3 * z**2).clamp(min=1e-6)\n    px  = pz / jac\n    # Numerical integration to verify p_X integrates to 1\n    dx  = (x[1:] - x[:-1]).abs()\n    px_mid = (px[1:] + px[:-1]) / 2\n    integral = (px_mid * dx).sum().item()\n    print(\u0027Integral of p_X (should be ~1): {:.4f}\u0027.format(integral))\n    # Log-likelihood at specific x values\n    for xi in [-8.0, 0.001, 8.0]:\n        zi  = np.sign(xi) * abs(xi) ** (1.0/3)\n        pzi = np.exp(-0.5 * zi**2) / np.sqrt(2 * np.pi)\n        pxi = pzi / (3 * zi**2 + 1e-8)\n        print(\u0027  x={:5.1f}  z={:.3f}  log p_X={:.3f}\u0027.format(\n              xi, zi, np.log(pxi + 1e-30)))\n\nchange_of_variables_demo()"},{"type":"heading","level":2,"content":"Tractable Jacobian Determinants"},{"type":"text","content":"The key computational challenge is computing log|det J_f|. For a general invertible neural network, this is O(d³). The solution is to design f with a triangular Jacobian, whose determinant is just the product of diagonal entries — O(d). A lower-triangular Jacobian arises from autoregressive models: x_i = f(x_{\u003ci}, z_i), so ∂x_i/∂z_j = 0 for j \u003e i. An upper-triangular Jacobian arises from coupling layers. Both enable O(d) log-determinant computation. This structural constraint on the Jacobian is the core design principle behind all practical flow architectures."},{"type":"heading","level":2,"content":"Coupling Layers: NICE and RealNVP"},{"type":"text","content":"NICE (Dinh et al. 2014) introduces additive coupling layers: split x into [x₁, x₂], pass x₁ through unchanged, and compute y₂ = x₂ + m(x₁) where m is an arbitrary neural network. The Jacobian is lower-triangular with 1s on the diagonal, so log|det J| = 0. Inversion is trivial: x₂ = y₂ − m(y₁). RealNVP extends this to affine coupling: y₂ = x₂ ⊙ exp(s(x₁)) + t(x₁). The Jacobian diagonal is exp(s(x₁)), giving log|det J| = Σᵢ sᵢ(x₁). Both s and t are unrestricted neural networks; only the coupling structure must be preserved."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass AdditiveCoupling(nn.Module):\n    \u0027\u0027\u0027NICE (Dinh 2014): y2 = x2 + m(x1), y1 = x1. log|det J| = 0.\u0027\u0027\u0027\n    def __init__(self, d, hidden=64):\n        super().__init__()\n        d1 = d // 2\n        self.d1 = d1\n        self.m  = nn.Sequential(\n            nn.Linear(d1, hidden), nn.ReLU(),\n            nn.Linear(hidden, hidden), nn.ReLU(),\n            nn.Linear(hidden, d - d1))\n\n    def forward(self, x):\n        x1, x2  = x[:, :self.d1], x[:, self.d1:]\n        y2       = x2 + self.m(x1)              # translate only\n        log_det  = torch.zeros(x.size(0))       # unit-volume map\n        return torch.cat([x1, y2], dim=1), log_det\n\n    def inverse(self, y):\n        y1, y2 = y[:, :self.d1], y[:, self.d1:]\n        x2     = y2 - self.m(y1)               # trivial inversion\n        return torch.cat([y1, x2], dim=1)\n\nlayer = AdditiveCoupling(d=8)\nx = torch.randn(4, 8)\ny, ld = layer(x)\nx_rec = layer.inverse(y)\nprint(\u0027Reconstruction error:\u0027, (x - x_rec).abs().max().item())\nprint(\u0027log|det J|:\u0027, ld.tolist())  # should be [0,0,0,0]"},{"type":"heading","level":2,"content":"Exact Log-Likelihood Computation"},{"type":"text","content":"A normalizing flow stacks K coupling layers: log p_X(x) = log p_Z(z_K) + Σₖ log|det J_fₖ(zₖ₋₁)|, where z₀ = x and z_K is the final latent. The sum of log-determinants accumulates across layers. Training directly maximises this exact log-likelihood — no variational bound, no score matching, no adversarial training. The exact likelihood also enables direct comparison between models in nats or bits-per-dim (BPD = −log₂ p(x) / D for D-dimensional x), unlike GANs where likelihood is unavailable."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.distributions as dist\n\nclass SimpleNICEFlow(nn.Module):\n    def __init__(self, d=8, n_layers=4, hidden=64):\n        super().__init__()\n        self.layers = nn.ModuleList(\n            [AdditiveCoupling(d, hidden=hidden) for _ in range(n_layers)])\n        self.prior  = dist.MultivariateNormal(\n            torch.zeros(d), torch.eye(d))\n\n    def log_prob(self, x):\n        z, log_det = x, torch.zeros(x.size(0))\n        for layer in self.layers:\n            z, ld = layer(z)\n            log_det = log_det + ld\n        return self.prior.log_prob(z) + log_det   # exact log p(x)\n\n    def sample(self, n):\n        z = self.prior.sample((n,))\n        for layer in reversed(self.layers):\n            z = layer.inverse(z)\n        return z\n\nflow = SimpleNICEFlow(d=8, n_layers=4)\nx = torch.randn(16, 8)\nlog_px = flow.log_prob(x)\nprint(\u0027Mean log p(x): {:.3f}  (NICE: log_det always 0, so = log p_Z(z))\u0027.format(\n      log_px.mean().item()))"},{"type":"callout","variant":"info","title":"Exact Likelihood vs Lower Bound vs Implicit","content":"VAEs maximise the ELBO = E[log p(x|z)] - KL(q(z|x) || p(z)), a lower bound on log p(x). The gap between ELBO and true log p(x) can be large. GANs have no likelihood at all — the model is implicit and likelihood cannot be computed. Flows compute log p(x) exactly via the change of variables formula. This makes flows uniquely suited for density estimation tasks, anomaly detection, and any application requiring calibrated probabilities."},{"type":"heading","level":2,"content":"Autoregressive Flows: MAF and IAF"},{"type":"text","content":"Masked Autoregressive Flow (MAF, Papamakarios 2017) uses an autoregressive model to define the scale-and-shift parameters: xᵢ = zᵢ · exp(sᵢ(x_{\u003ci})) + tᵢ(x_{\u003ci}). The Jacobian is lower-triangular so log|det J| = Σ sᵢ. MAF allows parallel density evaluation (all sᵢ can be computed in one forward pass of a MADE network) but requires sequential sampling. Inverse Autoregressive Flow (IAF) reverses this: sampling is parallel but density evaluation is sequential. MAF is better for density estimation; IAF is better for fast sampling (as in VAE decoders)."},{"type":"heading","level":2,"content":"Generative Sampling via Inversion"},{"type":"text","content":"To generate new samples from a flow: (1) sample z ~ p_Z = N(0,I) (trivially fast); (2) apply the inverse f⁻¹ to obtain x = f⁻¹(z). For coupling layers, the inverse is analytically tractable and fast — O(d) per layer, and all dimensions can be computed in parallel. For autoregressive flows (MAF), inversion requires d sequential steps — one per dimension. This sequential dependency makes autoregressive flows slower at generation; coupling-layer flows (RealNVP, Glow) are preferred when fast sampling matters."},{"type":"code","language":"python","content":"import torch\n\ndef flow_sample_and_evaluate(flow, n_samples=16):\n    \u0027\u0027\u0027Generate samples via inversion; compute their log-likelihoods.\u0027\u0027\u0027\n    flow.eval()\n    with torch.no_grad():\n        samples = flow.sample(n_samples)\n        log_px  = flow.log_prob(samples)\n    print(\u0027Samples shape : {}\u0027.format(samples.shape))\n    print(\u0027Sample mean   : {:.4f}\u0027.format(samples.mean().item()))\n    print(\u0027Sample std    : {:.4f}\u0027.format(samples.std().item()))\n    print(\u0027Mean log p(x) : {:.3f}\u0027.format(log_px.mean().item()))\n    print(\u0027BPD (bits/dim): {:.3f}\u0027.format(-log_px.mean().item() / (8 * 0.6931)))\n    return samples\n\nflow = SimpleNICEFlow(d=8, n_layers=4)\nsamples = flow_sample_and_evaluate(flow)\nprint(\u0027Flows: exact likelihood + O(d) parallel sampling via coupling inversion.\u0027)"},{"type":"list","ordered":false,"items":["Exact log-likelihood: log p_X(x) = log p_Z(f(x)) + log|det J_f(x)| — no bound, no approximation.","Coupling layers: triangular Jacobian with O(d) determinant; parallel forward and inverse.","Additive coupling (NICE): log|det J| = 0; volume-preserving; limited expressivity.","Affine coupling (RealNVP): log|det J| = sum of log-scales; more expressive.","MAF: parallel density estimation, sequential sampling — best for density estimation tasks.","IAF: parallel sampling, sequential density — used in VAE decoders for fast generation.","Glow: 1x1 invertible convolutions + affine coupling for high-resolution image synthesis."]},{"type":"heading","level":2,"content":"Comparison: VAE vs GAN vs Flow vs Diffusion"},{"type":"table","headers":["Property","VAE","GAN","Normalizing Flow","Diffusion"],"rows":[["Exact likelihood","No (ELBO lower bound)","No (implicit)","Yes (change of vars)","No (but tractable bound)"],["Sample quality","Medium","High","Medium","Very high"],["Training stability","Stable","Unstable (adversarial)","Stable (MLE)","Stable"],["Sample speed","Fast (1-step decode)","Fast (1-step G)","Fast (coupling inverse)","Slow (many denoising steps)"],["Latent space","Yes, structured","Partial (z)","Yes, exact inverse","Noise sequence"]]},{"type":"divider"}]"
---
# Normalizing Flows — Change of Variables and Exact Likelihood

A normalizing flow is a generative model that learns a bijective (invertible) function f: X ↔ Z, where Z follows a simple base distribution such as N(0,I). The name comes from the idea that the transformation 'normalises' the complex data distribution into a Gaussian. Flows offer a property unique among deep generative models: exact log-likelihood computation. Unlike VAEs (lower bound) and GANs (implicit distribution), flows give the exact log p(x) via the change of variables formula, enabling direct maximum likelihood training.

## Change of Variables Formula

If Z ~ p_Z and x = f⁻¹(z) where f is bijective, then the density of X satisfies: p_X(x) = p_Z(f(x)) |det J_f(x)|. Taking logs: log p_X(x) = log p_Z(f(x)) + log|det J_f(x)|. The first term is the log-likelihood under the simple base distribution. The second term is the log absolute Jacobian determinant of f — it accounts for how f stretches or compresses volume. Training maximises E_x[log p_X(x)] over the dataset. The challenge: for a general neural network, computing det J_f costs O(d³) for a d-dimensional input — prohibitive for images.

```python
import torch
import numpy as np

def change_of_variables_demo():
    '''1D: Z ~ N(0,1), x = f^{-1}(z) = z^3. Verify p_X integrates to 1.'''
    z = torch.linspace(-2.5, 2.5, 1000)
    x = z ** 3              # forward map: z -> x
    # Change of variables: p_X(x) = p_Z(z) / |df/dz|
    # df/dz = 3z^2, so p_X = p_Z(z) / (3z^2)
    pz  = torch.exp(-0.5 * z**2) / (2 * torch.pi) ** 0.5
    jac = (3 * z**2).clamp(min=1e-6)
    px  = pz / jac
    # Numerical integration to verify p_X integrates to 1
    dx  = (x[1:] - x[:-1]).abs()
    px_mid = (px[1:] + px[:-1]) / 2
    integral = (px_mid * dx).sum().item()
    print('Integral of p_X (should be ~1): {:.4f}'.format(integral))
    # Log-likelihood at specific x values
    for xi in [-8.0, 0.001, 8.0]:
        zi  = np.sign(xi) * abs(xi) ** (1.0/3)
        pzi = np.exp(-0.5 * zi**2) / np.sqrt(2 * np.pi)
        pxi = pzi / (3 * zi**2 + 1e-8)
        print('  x={:5.1f}  z={:.3f}  log p_X={:.3f}'.format(
              xi, zi, np.log(pxi + 1e-30)))

change_of_variables_demo()
```

## Tractable Jacobian Determinants

The key computational challenge is computing log|det J_f|. For a general invertible neural network, this is O(d³). The solution is to design f with a triangular Jacobian, whose determinant is just the product of diagonal entries — O(d). A lower-triangular Jacobian arises from autoregressive models: x_i = f(x_{<i}, z_i), so ∂x_i/∂z_j = 0 for j > i. An upper-triangular Jacobian arises from coupling layers. Both enable O(d) log-determinant computation. This structural constraint on the Jacobian is the core design principle behind all practical flow architectures.

## Coupling Layers: NICE and RealNVP

NICE (Dinh et al. 2014) introduces additive coupling layers: split x into [x₁, x₂], pass x₁ through unchanged, and compute y₂ = x₂ + m(x₁) where m is an arbitrary neural network. The Jacobian is lower-triangular with 1s on the diagonal, so log|det J| = 0. Inversion is trivial: x₂ = y₂ − m(y₁). RealNVP extends this to affine coupling: y₂ = x₂ ⊙ exp(s(x₁)) + t(x₁). The Jacobian diagonal is exp(s(x₁)), giving log|det J| = Σᵢ sᵢ(x₁). Both s and t are unrestricted neural networks; only the coupling structure must be preserved.

```python
import torch
import torch.nn as nn

class AdditiveCoupling(nn.Module):
    '''NICE (Dinh 2014): y2 = x2 + m(x1), y1 = x1. log|det J| = 0.'''
    def __init__(self, d, hidden=64):
        super().__init__()
        d1 = d // 2
        self.d1 = d1
        self.m  = nn.Sequential(
            nn.Linear(d1, hidden), nn.ReLU(),
            nn.Linear(hidden, hidden), nn.ReLU(),
            nn.Linear(hidden, d - d1))

    def forward(self, x):
        x1, x2  = x[:, :self.d1], x[:, self.d1:]
        y2       = x2 + self.m(x1)              # translate only
        log_det  = torch.zeros(x.size(0))       # unit-volume map
        return torch.cat([x1, y2], dim=1), log_det

    def inverse(self, y):
        y1, y2 = y[:, :self.d1], y[:, self.d1:]
        x2     = y2 - self.m(y1)               # trivial inversion
        return torch.cat([y1, x2], dim=1)

layer = AdditiveCoupling(d=8)
x = torch.randn(4, 8)
y, ld = layer(x)
x_rec = layer.inverse(y)
print('Reconstruction error:', (x - x_rec).abs().max().item())
print('log|det J|:', ld.tolist())  # should be [0,0,0,0]
```

## Exact Log-Likelihood Computation

A normalizing flow stacks K coupling layers: log p_X(x) = log p_Z(z_K) + Σₖ log|det J_fₖ(zₖ₋₁)|, where z₀ = x and z_K is the final latent. The sum of log-determinants accumulates across layers. Training directly maximises this exact log-likelihood — no variational bound, no score matching, no adversarial training. The exact likelihood also enables direct comparison between models in nats or bits-per-dim (BPD = −log₂ p(x) / D for D-dimensional x), unlike GANs where likelihood is unavailable.

```python
import torch
import torch.nn as nn
import torch.distributions as dist

class SimpleNICEFlow(nn.Module):
    def __init__(self, d=8, n_layers=4, hidden=64):
        super().__init__()
        self.layers = nn.ModuleList(
            [AdditiveCoupling(d, hidden=hidden) for _ in range(n_layers)])
        self.prior  = dist.MultivariateNormal(
            torch.zeros(d), torch.eye(d))

    def log_prob(self, x):
        z, log_det = x, torch.zeros(x.size(0))
        for layer in self.layers:
            z, ld = layer(z)
            log_det = log_det + ld
        return self.prior.log_prob(z) + log_det   # exact log p(x)

    def sample(self, n):
        z = self.prior.sample((n,))
        for layer in reversed(self.layers):
            z = layer.inverse(z)
        return z

flow = SimpleNICEFlow(d=8, n_layers=4)
x = torch.randn(16, 8)
log_px = flow.log_prob(x)
print('Mean log p(x): {:.3f}  (NICE: log_det always 0, so = log p_Z(z))'.format(
      log_px.mean().item()))
```

> **Exact Likelihood vs Lower Bound vs Implicit**: VAEs maximise the ELBO = E[log p(x|z)] - KL(q(z|x) || p(z)), a lower bound on log p(x). The gap between ELBO and true log p(x) can be large. GANs have no likelihood at all — the model is implicit and likelihood cannot be computed. Flows compute log p(x) exactly via the change of variables formula. This makes flows uniquely suited for density estimation tasks, anomaly detection, and any application requiring calibrated probabilities.

## Autoregressive Flows: MAF and IAF

Masked Autoregressive Flow (MAF, Papamakarios 2017) uses an autoregressive model to define the scale-and-shift parameters: xᵢ = zᵢ · exp(sᵢ(x_{<i})) + tᵢ(x_{<i}). The Jacobian is lower-triangular so log|det J| = Σ sᵢ. MAF allows parallel density evaluation (all sᵢ can be computed in one forward pass of a MADE network) but requires sequential sampling. Inverse Autoregressive Flow (IAF) reverses this: sampling is parallel but density evaluation is sequential. MAF is better for density estimation; IAF is better for fast sampling (as in VAE decoders).

## Generative Sampling via Inversion

To generate new samples from a flow: (1) sample z ~ p_Z = N(0,I) (trivially fast); (2) apply the inverse f⁻¹ to obtain x = f⁻¹(z). For coupling layers, the inverse is analytically tractable and fast — O(d) per layer, and all dimensions can be computed in parallel. For autoregressive flows (MAF), inversion requires d sequential steps — one per dimension. This sequential dependency makes autoregressive flows slower at generation; coupling-layer flows (RealNVP, Glow) are preferred when fast sampling matters.

```python
import torch

def flow_sample_and_evaluate(flow, n_samples=16):
    '''Generate samples via inversion; compute their log-likelihoods.'''
    flow.eval()
    with torch.no_grad():
        samples = flow.sample(n_samples)
        log_px  = flow.log_prob(samples)
    print('Samples shape : {}'.format(samples.shape))
    print('Sample mean   : {:.4f}'.format(samples.mean().item()))
    print('Sample std    : {:.4f}'.format(samples.std().item()))
    print('Mean log p(x) : {:.3f}'.format(log_px.mean().item()))
    print('BPD (bits/dim): {:.3f}'.format(-log_px.mean().item() / (8 * 0.6931)))
    return samples

flow = SimpleNICEFlow(d=8, n_layers=4)
samples = flow_sample_and_evaluate(flow)
print('Flows: exact likelihood + O(d) parallel sampling via coupling inversion.')
```

- Exact log-likelihood: log p_X(x) = log p_Z(f(x)) + log|det J_f(x)| — no bound, no approximation.
- Coupling layers: triangular Jacobian with O(d) determinant; parallel forward and inverse.
- Additive coupling (NICE): log|det J| = 0; volume-preserving; limited expressivity.
- Affine coupling (RealNVP): log|det J| = sum of log-scales; more expressive.
- MAF: parallel density estimation, sequential sampling — best for density estimation tasks.
- IAF: parallel sampling, sequential density — used in VAE decoders for fast generation.
- Glow: 1x1 invertible convolutions + affine coupling for high-resolution image synthesis.

## Comparison: VAE vs GAN vs Flow vs Diffusion

| Property | VAE | GAN | Normalizing Flow | Diffusion |
| --- | --- | --- | --- | --- |
| Exact likelihood | No (ELBO lower bound) | No (implicit) | Yes (change of vars) | No (but tractable bound) |
| Sample quality | Medium | High | Medium | Very high |
| Training stability | Stable | Unstable (adversarial) | Stable (MLE) | Stable |
| Sample speed | Fast (1-step decode) | Fast (1-step G) | Fast (coupling inverse) | Slow (many denoising steps) |
| Latent space | Yes, structured | Partial (z) | Yes, exact inverse | Noise sequence |

---

