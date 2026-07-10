---
title: "DDPM — Forward Process and Reverse Denoising"
slug: "ddpm-denoising-diffusion"
description: "DDPM (Ho et al. 2020) defines a T=1000-step Markov chain that gradually adds Gaussian noise (forward) and learns to reverse it (reverse process). Covers the closed-form q(x_t|x_0), linear vs cosine beta schedules, U-Net with time embedding, and the full sampling loop."
tags: ["deep-learning", "generative-models", "diffusion-models", "normalizing-flows"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"DDPM (Ho et al., 2020) defines a generative model as the reverse of a fixed forward Markov chain that gradually corrupts data with Gaussian noise. The forward process q(x_t | x_{t-1}) = N(x_t; √(1-β_t) x_{t-1}, β_t I) has a closed-form marginal q(x_t | x_0) = N(x_t; √α̅_t x_0, (1-α̅_t) I), allowing direct sampling at any noise level without simulation. A U-Net learns to reverse this process: given noisy x_t and timestep t, predict the noise ε that was added. At generation, the model starts from x_T ~ N(0,I) and iteratively denoises over T=1000 steps."},{"type":"heading","level":2,"content":"Forward Diffusion Process"},{"type":"text","content":"The forward process adds noise step-by-step: q(x_t | x_{t-1}) = N(x_t; √(1-β_t) x_{t-1}, β_t I). The signal is attenuated by √(1-β_t) at each step while Gaussian noise of variance β_t is added. Because each step is Gaussian, the marginal q(x_t | x_0) is also Gaussian with a closed-form expression: x_t = √α̅_t x_0 + √(1-α̅_t) ε, ε ~ N(0,I), where α̅_t = Π_{s=1}^{t} (1-β_s). This lets us corrupt x_0 to any timestep t in one step, enabling efficient training by sampling t uniformly."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef make_alpha_bar(beta):\n    \"\"\"Cumulative product: alpha_bar_t = prod_{s=1}^{t} (1 - beta_s).\"\"\"\n    return torch.cumprod(1.0 - beta, dim=0)\n\ndef q_sample(x0, t, alpha_bar, noise=None):\n    \"\"\"\n    Closed-form forward process: q(x_t | x_0).\n    x_t = sqrt(alpha_bar_t) * x0 + sqrt(1 - alpha_bar_t) * eps\n    Allows jumping directly to any noise level without T sequential steps.\n    \"\"\"\n    if noise is None:\n        noise = torch.randn_like(x0)\n    ab   = alpha_bar[t].view(-1, 1, 1, 1)\n    return ab.sqrt() * x0 + (1 - ab).sqrt() * noise, noise\n\nT    = 1000\nbeta = torch.linspace(1e-4, 0.02, T)\nab   = make_alpha_bar(beta)\nx0   = torch.randn(4, 3, 32, 32)\nt    = torch.tensor([0, 249, 499, 999])\nxt, noise = q_sample(x0, t, ab)\nprint(f\"x0: {x0.shape}  xt: {xt.shape}\")\nfor i, ti in enumerate(t.tolist()):\n    snr = (ab[ti] / (1 - ab[ti])).item()\n    print(f\"  t={ti:4d}: alpha_bar={ab[ti]:.4f}  SNR={snr:.4f}\")"},{"type":"heading","level":2,"content":"Noise Schedules"},{"type":"text","content":"The β_t schedule controls how quickly signal is destroyed. The original DDPM uses a linear schedule: β_t increases linearly from 10^{-4} to 0.02 over T=1000 steps. Improved DDPM (Nichol \u0026 Dhariwal, 2021) found that this schedule destroys signal too aggressively at small t and introduced a cosine schedule where α̅_t = cos²(π/2 × (t/T + s)/(1+s)), resulting in a smoother signal-to-noise ratio trajectory. The cosine schedule improves sample quality, especially for high-resolution images."},{"type":"code","language":"python","content":"import torch\nimport math\n\ndef linear_schedule(T=1000, b_start=1e-4, b_end=0.02):\n    \"\"\"Original DDPM linear beta schedule.\"\"\"\n    return torch.linspace(b_start, b_end, T)\n\ndef cosine_schedule(T=1000, s=0.008):\n    \"\"\"\n    Cosine schedule (Nichol \u0026 Dhariwal 2021).\n    alpha_bar_t = cos^2( pi/2 * (t/T + s) / (1 + s) )\n    Avoids over-destruction of signal at small t.\n    \"\"\"\n    steps = torch.arange(T + 1, dtype=torch.float64)\n    f     = torch.cos(((steps / T + s) / (1 + s)) * (math.pi / 2)) ** 2\n    ab    = (f / f[0]).float()\n    beta  = (1 - ab[1:] / ab[:-1]).clamp(0, 0.999)\n    return beta, ab[1:]\n\nbeta_lin  = linear_schedule()\nab_lin    = torch.cumprod(1 - beta_lin, dim=0)\nbeta_cos, ab_cos = cosine_schedule()\n\nfor label, ab in [(\u0027Linear \u0027, ab_lin), (\u0027Cosine \u0027, ab_cos)]:\n    vals = [ab[i].item() for i in [0, 249, 499, 749, 999]]\n    print(f\"{label} alpha_bar at t=0,250,500,750,999: \"\n          + \u0027  \u0027.join(f\u0027{v:.4f}\u0027 for v in vals))\nprint(\"Cosine: slower signal decay at low t, similar total at T\")\nprint(\"Linear: reaches near-zero signal at t\u003cT/2 -- problematic for high res\")"},{"type":"heading","level":2,"content":"Closed-Form Noising and Why It Matters"},{"type":"text","content":"The closed-form q(x_t | x_0) is the key that makes DDPM training tractable. Without it, computing x_t would require simulating t steps of the Markov chain for each training example, making sampling of high t computationally expensive. With the closed form, training samples a timestep t ~ Uniform[1, T] uniformly, computes x_t = √α̅_t x_0 + √(1-α̅_t) ε in a single operation, and trains the denoiser to predict ε. This reparameterization also means the network sees data at all noise levels equally often during training."},{"type":"heading","level":2,"content":"Reverse Process and U-Net Denoiser"},{"type":"text","content":"The reverse process p_θ(x_{t-1} | x_t) = N(x_{t-1}; μ_θ(x_t, t), Σ_θ) is parameterized by a U-Net. The U-Net takes x_t and timestep t as inputs and predicts the noise ε (or equivalently x_0). Timestep t is encoded with sinusoidal positional embeddings (matching Transformer-style embeddings) and injected into each residual block via an affine projection. Skip connections in the U-Net preserve spatial information, and attention layers at lower resolutions capture global structure."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport math\n\nclass SinTimeEmb(nn.Module):\n    def __init__(self, dim):\n        super().__init__()\n        self.lin = nn.Sequential(nn.Linear(dim, dim * 4), nn.SiLU(), nn.Linear(dim * 4, dim))\n        self.dim = dim\n    def forward(self, t):\n        half = self.dim // 2\n        f = torch.exp(-math.log(10000) * torch.arange(half).float() / half)\n        e = t.float().unsqueeze(1) * f.unsqueeze(0)\n        return self.lin(torch.cat([e.sin(), e.cos()], dim=-1))\n\nclass ResBlock(nn.Module):\n    def __init__(self, c, t_dim):\n        super().__init__()\n        self.norm1  = nn.GroupNorm(4, c)\n        self.conv1  = nn.Conv2d(c, c, 3, padding=1)\n        self.t_proj = nn.Linear(t_dim, c)\n        self.norm2  = nn.GroupNorm(4, c)\n        self.conv2  = nn.Conv2d(c, c, 3, padding=1)\n    def forward(self, x, t_emb):\n        h = self.conv1(F.silu(self.norm1(x)))\n        h = h + self.t_proj(t_emb)[:, :, None, None]\n        return self.conv2(F.silu(self.norm2(h))) + x\n\nclass SimpleUNet(nn.Module):\n    def __init__(self, c_in=3, c=64, t_dim=128):\n        super().__init__()\n        self.t_emb = SinTimeEmb(t_dim)\n        self.proj  = nn.Conv2d(c_in, c, 1)\n        self.blk   = ResBlock(c, t_dim)\n        self.out   = nn.Conv2d(c, c_in, 1)\n    def forward(self, x, t):\n        return self.out(self.blk(self.proj(x), self.t_emb(t)))\n\nmodel = SimpleUNet()\nx = torch.randn(4, 3, 32, 32)\nt = torch.randint(0, 1000, (4,))\nprint(f\"Input: {x.shape} -\u003e Noise pred: {model(x, t).shape}\")\nprint(\"Time embedding: sinusoidal -\u003e MLP -\u003e injected in each ResBlock\")"},{"type":"heading","level":2,"content":"DDPM Sampling Loop"},{"type":"text","content":"Generation starts from x_T ~ N(0, I) and iteratively applies the reverse step. At each step t, the model predicts ε, recovers an estimate of x_0, computes the posterior mean μ̃_t, and adds stochastic noise scaled by β_t (except at t=0). The posterior variance is fixed to β̃_t = β_t(1-α̅_{t-1}) / (1-α̅_t). After T=1000 steps, x_0 is the generated sample. The sampling is slow (T model evaluations); subsequent work (DDIM, DPM-Solver) reduces this to 10-50 steps."},{"type":"code","language":"python","content":"import torch\n\n@torch.no_grad()\ndef ddpm_sample(model, T, beta, alpha_bar, shape, device=\u0027cpu\u0027):\n    \"\"\"DDPM ancestral sampling: start from x_T ~ N(0,I), denoise T steps.\"\"\"\n    alpha  = 1.0 - beta\n    model.eval()\n    x = torch.randn(*shape, device=device)\n    for t_idx in reversed(range(T)):\n        t_b   = torch.full((shape[0],), t_idx, device=device, dtype=torch.long)\n        eps_p = model(x, t_b)                # predicted noise\n        ab_t  = alpha_bar[t_idx]\n        ab_p  = alpha_bar[t_idx - 1] if t_idx \u003e 0 else torch.tensor(1.0)\n        bt    = beta[t_idx]\n        # Estimate x0 and compute posterior mean\n        x0_hat = (x - (1 - ab_t).sqrt() * eps_p) / ab_t.sqrt()\n        x0_hat = x0_hat.clamp(-1, 1)\n        c1 = ab_p.sqrt() * bt / (1 - ab_t)\n        c2 = alpha[t_idx].sqrt() * (1 - ab_p) / (1 - ab_t)\n        mu = c1 * x0_hat + c2 * x\n        noise = torch.randn_like(x) if t_idx \u003e 0 else torch.zeros_like(x)\n        x = mu + bt.sqrt() * noise\n        if t_idx % 250 == 0:\n            print(f\"  t={t_idx:4d}  x.std={x.std():.3f}  x0_hat.std={x0_hat.std():.3f}\")\n    return x\n\nT = 1000\nbeta      = torch.linspace(1e-4, 0.02, T)\nalpha_bar = torch.cumprod(1 - beta, dim=0)\nmodel     = SimpleUNet()\nsample    = ddpm_sample(model, T, beta, alpha_bar, shape=(1, 3, 32, 32))\nprint(f\"Sample shape: {sample.shape}\")"},{"type":"callout","variant":"info","title":"Why T=1000 Steps?","content":"Fewer steps means larger β_t per step, making the Gaussian reverse approximation p_θ(x_{t-1}|x_t) ≈ N(μ_θ, Σ_θ) less accurate (the true reverse is non-Gaussian for large β). T=1000 ensures each step is small enough that the Gaussian approximation holds. DDIM (Song et al. 2020) reformulates sampling to skip steps deterministically, achieving comparable quality in 10-50 steps without retraining."},{"type":"heading","level":2,"content":"Key DDPM Equations"},{"type":"table","headers":["Equation","Formula","Purpose"],"rows":[["Forward q(x_t|x_{t-1})","N(x_t; sqrt(1-beta_t) x_{t-1}, beta_t I)","Add small Gaussian noise at each step"],["Closed form q(x_t|x_0)","N(x_t; sqrt(ab_t) x_0, (1-ab_t) I)","Jump to any noise level in one step"],["Reverse p_theta(x_{t-1}|x_t)","N(x_{t-1}; mu_theta(x_t,t), sigma_t^2 I)","Learned Gaussian denoising step"],["Simplified loss L_simple","E[||eps - eps_theta(sqrt(ab_t) x0 + sqrt(1-ab_t) eps, t)||^2]","Train denoiser to predict added noise"],["Posterior mean mu_tilde_t","(sqrt(ab_{t-1}) beta_t x0 + sqrt(alpha_t)(1-ab_{t-1}) xt) / (1-ab_t)","Tractable reverse posterior mean"]]},{"type":"heading","level":2,"content":"Summary and Insights"},{"type":"text","content":"DDPM achieves high sample quality by breaking generation into T small denoising steps, each easy to learn individually. The closed-form forward process and simplified noise-prediction loss make training straightforward. The main drawbacks are slow sampling (T model evaluations) and the absence of an encoder (unlike VAEs or flows). Subsequent work addresses these: DDIM for fast deterministic sampling, latent diffusion models for efficiency, and classifier-free guidance for conditioning."},{"type":"list","ordered":false,"items":["Forward process: fixed Markov chain with closed-form marginals -- no parameters to learn.","Training: sample t ~ Uniform, corrupt x0 to xt in one step, minimize ||eps - eps_hat||^2.","Reverse: T Gaussian steps learned by U-Net conditioned on timestep t via sinusoidal embedding.","Beta schedule: linear (original) or cosine (improved) -- cosine better at preserving low-t signal.","Sample quality: competitive with GANs on CIFAR-10 FID without adversarial training.","Sampling speed: T=1000 forward passes -- the main bottleneck addressed by DDIM/DPM-Solver."]},{"type":"divider"}]"
---
# DDPM — Forward Process and Reverse Denoising

DDPM (Ho et al., 2020) defines a generative model as the reverse of a fixed forward Markov chain that gradually corrupts data with Gaussian noise. The forward process q(x_t | x_{t-1}) = N(x_t; √(1-β_t) x_{t-1}, β_t I) has a closed-form marginal q(x_t | x_0) = N(x_t; √α̅_t x_0, (1-α̅_t) I), allowing direct sampling at any noise level without simulation. A U-Net learns to reverse this process: given noisy x_t and timestep t, predict the noise ε that was added. At generation, the model starts from x_T ~ N(0,I) and iteratively denoises over T=1000 steps.

## Forward Diffusion Process

The forward process adds noise step-by-step: q(x_t | x_{t-1}) = N(x_t; √(1-β_t) x_{t-1}, β_t I). The signal is attenuated by √(1-β_t) at each step while Gaussian noise of variance β_t is added. Because each step is Gaussian, the marginal q(x_t | x_0) is also Gaussian with a closed-form expression: x_t = √α̅_t x_0 + √(1-α̅_t) ε, ε ~ N(0,I), where α̅_t = Π_{s=1}^{t} (1-β_s). This lets us corrupt x_0 to any timestep t in one step, enabling efficient training by sampling t uniformly.

```python
import torch
import numpy as np

def make_alpha_bar(beta):
    """Cumulative product: alpha_bar_t = prod_{s=1}^{t} (1 - beta_s)."""
    return torch.cumprod(1.0 - beta, dim=0)

def q_sample(x0, t, alpha_bar, noise=None):
    """
    Closed-form forward process: q(x_t | x_0).
    x_t = sqrt(alpha_bar_t) * x0 + sqrt(1 - alpha_bar_t) * eps
    Allows jumping directly to any noise level without T sequential steps.
    """
    if noise is None:
        noise = torch.randn_like(x0)
    ab   = alpha_bar[t].view(-1, 1, 1, 1)
    return ab.sqrt() * x0 + (1 - ab).sqrt() * noise, noise

T    = 1000
beta = torch.linspace(1e-4, 0.02, T)
ab   = make_alpha_bar(beta)
x0   = torch.randn(4, 3, 32, 32)
t    = torch.tensor([0, 249, 499, 999])
xt, noise = q_sample(x0, t, ab)
print(f"x0: {x0.shape}  xt: {xt.shape}")
for i, ti in enumerate(t.tolist()):
    snr = (ab[ti] / (1 - ab[ti])).item()
    print(f"  t={ti:4d}: alpha_bar={ab[ti]:.4f}  SNR={snr:.4f}")
```

## Noise Schedules

The β_t schedule controls how quickly signal is destroyed. The original DDPM uses a linear schedule: β_t increases linearly from 10^{-4} to 0.02 over T=1000 steps. Improved DDPM (Nichol & Dhariwal, 2021) found that this schedule destroys signal too aggressively at small t and introduced a cosine schedule where α̅_t = cos²(π/2 × (t/T + s)/(1+s)), resulting in a smoother signal-to-noise ratio trajectory. The cosine schedule improves sample quality, especially for high-resolution images.

```python
import torch
import math

def linear_schedule(T=1000, b_start=1e-4, b_end=0.02):
    """Original DDPM linear beta schedule."""
    return torch.linspace(b_start, b_end, T)

def cosine_schedule(T=1000, s=0.008):
    """
    Cosine schedule (Nichol & Dhariwal 2021).
    alpha_bar_t = cos^2( pi/2 * (t/T + s) / (1 + s) )
    Avoids over-destruction of signal at small t.
    """
    steps = torch.arange(T + 1, dtype=torch.float64)
    f     = torch.cos(((steps / T + s) / (1 + s)) * (math.pi / 2)) ** 2
    ab    = (f / f[0]).float()
    beta  = (1 - ab[1:] / ab[:-1]).clamp(0, 0.999)
    return beta, ab[1:]

beta_lin  = linear_schedule()
ab_lin    = torch.cumprod(1 - beta_lin, dim=0)
beta_cos, ab_cos = cosine_schedule()

for label, ab in [('Linear ', ab_lin), ('Cosine ', ab_cos)]:
    vals = [ab[i].item() for i in [0, 249, 499, 749, 999]]
    print(f"{label} alpha_bar at t=0,250,500,750,999: "
          + '  '.join(f'{v:.4f}' for v in vals))
print("Cosine: slower signal decay at low t, similar total at T")
print("Linear: reaches near-zero signal at t<T/2 -- problematic for high res")
```

## Closed-Form Noising and Why It Matters

The closed-form q(x_t | x_0) is the key that makes DDPM training tractable. Without it, computing x_t would require simulating t steps of the Markov chain for each training example, making sampling of high t computationally expensive. With the closed form, training samples a timestep t ~ Uniform[1, T] uniformly, computes x_t = √α̅_t x_0 + √(1-α̅_t) ε in a single operation, and trains the denoiser to predict ε. This reparameterization also means the network sees data at all noise levels equally often during training.

## Reverse Process and U-Net Denoiser

The reverse process p_θ(x_{t-1} | x_t) = N(x_{t-1}; μ_θ(x_t, t), Σ_θ) is parameterized by a U-Net. The U-Net takes x_t and timestep t as inputs and predicts the noise ε (or equivalently x_0). Timestep t is encoded with sinusoidal positional embeddings (matching Transformer-style embeddings) and injected into each residual block via an affine projection. Skip connections in the U-Net preserve spatial information, and attention layers at lower resolutions capture global structure.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import math

class SinTimeEmb(nn.Module):
    def __init__(self, dim):
        super().__init__()
        self.lin = nn.Sequential(nn.Linear(dim, dim * 4), nn.SiLU(), nn.Linear(dim * 4, dim))
        self.dim = dim
    def forward(self, t):
        half = self.dim // 2
        f = torch.exp(-math.log(10000) * torch.arange(half).float() / half)
        e = t.float().unsqueeze(1) * f.unsqueeze(0)
        return self.lin(torch.cat([e.sin(), e.cos()], dim=-1))

class ResBlock(nn.Module):
    def __init__(self, c, t_dim):
        super().__init__()
        self.norm1  = nn.GroupNorm(4, c)
        self.conv1  = nn.Conv2d(c, c, 3, padding=1)
        self.t_proj = nn.Linear(t_dim, c)
        self.norm2  = nn.GroupNorm(4, c)
        self.conv2  = nn.Conv2d(c, c, 3, padding=1)
    def forward(self, x, t_emb):
        h = self.conv1(F.silu(self.norm1(x)))
        h = h + self.t_proj(t_emb)[:, :, None, None]
        return self.conv2(F.silu(self.norm2(h))) + x

class SimpleUNet(nn.Module):
    def __init__(self, c_in=3, c=64, t_dim=128):
        super().__init__()
        self.t_emb = SinTimeEmb(t_dim)
        self.proj  = nn.Conv2d(c_in, c, 1)
        self.blk   = ResBlock(c, t_dim)
        self.out   = nn.Conv2d(c, c_in, 1)
    def forward(self, x, t):
        return self.out(self.blk(self.proj(x), self.t_emb(t)))

model = SimpleUNet()
x = torch.randn(4, 3, 32, 32)
t = torch.randint(0, 1000, (4,))
print(f"Input: {x.shape} -> Noise pred: {model(x, t).shape}")
print("Time embedding: sinusoidal -> MLP -> injected in each ResBlock")
```

## DDPM Sampling Loop

Generation starts from x_T ~ N(0, I) and iteratively applies the reverse step. At each step t, the model predicts ε, recovers an estimate of x_0, computes the posterior mean μ̃_t, and adds stochastic noise scaled by β_t (except at t=0). The posterior variance is fixed to β̃_t = β_t(1-α̅_{t-1}) / (1-α̅_t). After T=1000 steps, x_0 is the generated sample. The sampling is slow (T model evaluations); subsequent work (DDIM, DPM-Solver) reduces this to 10-50 steps.

```python
import torch

@torch.no_grad()
def ddpm_sample(model, T, beta, alpha_bar, shape, device='cpu'):
    """DDPM ancestral sampling: start from x_T ~ N(0,I), denoise T steps."""
    alpha  = 1.0 - beta
    model.eval()
    x = torch.randn(*shape, device=device)
    for t_idx in reversed(range(T)):
        t_b   = torch.full((shape[0],), t_idx, device=device, dtype=torch.long)
        eps_p = model(x, t_b)                # predicted noise
        ab_t  = alpha_bar[t_idx]
        ab_p  = alpha_bar[t_idx - 1] if t_idx > 0 else torch.tensor(1.0)
        bt    = beta[t_idx]
        # Estimate x0 and compute posterior mean
        x0_hat = (x - (1 - ab_t).sqrt() * eps_p) / ab_t.sqrt()
        x0_hat = x0_hat.clamp(-1, 1)
        c1 = ab_p.sqrt() * bt / (1 - ab_t)
        c2 = alpha[t_idx].sqrt() * (1 - ab_p) / (1 - ab_t)
        mu = c1 * x0_hat + c2 * x
        noise = torch.randn_like(x) if t_idx > 0 else torch.zeros_like(x)
        x = mu + bt.sqrt() * noise
        if t_idx % 250 == 0:
            print(f"  t={t_idx:4d}  x.std={x.std():.3f}  x0_hat.std={x0_hat.std():.3f}")
    return x

T = 1000
beta      = torch.linspace(1e-4, 0.02, T)
alpha_bar = torch.cumprod(1 - beta, dim=0)
model     = SimpleUNet()
sample    = ddpm_sample(model, T, beta, alpha_bar, shape=(1, 3, 32, 32))
print(f"Sample shape: {sample.shape}")
```

> **Why T=1000 Steps?**: Fewer steps means larger β_t per step, making the Gaussian reverse approximation p_θ(x_{t-1}|x_t) ≈ N(μ_θ, Σ_θ) less accurate (the true reverse is non-Gaussian for large β). T=1000 ensures each step is small enough that the Gaussian approximation holds. DDIM (Song et al. 2020) reformulates sampling to skip steps deterministically, achieving comparable quality in 10-50 steps without retraining.

## Key DDPM Equations

| Equation | Formula | Purpose |
| --- | --- | --- |
| Forward q(x_t|x_{t-1}) | N(x_t; sqrt(1-beta_t) x_{t-1}, beta_t I) | Add small Gaussian noise at each step |
| Closed form q(x_t|x_0) | N(x_t; sqrt(ab_t) x_0, (1-ab_t) I) | Jump to any noise level in one step |
| Reverse p_theta(x_{t-1}|x_t) | N(x_{t-1}; mu_theta(x_t,t), sigma_t^2 I) | Learned Gaussian denoising step |
| Simplified loss L_simple | E[||eps - eps_theta(sqrt(ab_t) x0 + sqrt(1-ab_t) eps, t)||^2] | Train denoiser to predict added noise |
| Posterior mean mu_tilde_t | (sqrt(ab_{t-1}) beta_t x0 + sqrt(alpha_t)(1-ab_{t-1}) xt) / (1-ab_t) | Tractable reverse posterior mean |

## Summary and Insights

DDPM achieves high sample quality by breaking generation into T small denoising steps, each easy to learn individually. The closed-form forward process and simplified noise-prediction loss make training straightforward. The main drawbacks are slow sampling (T model evaluations) and the absence of an encoder (unlike VAEs or flows). Subsequent work addresses these: DDIM for fast deterministic sampling, latent diffusion models for efficiency, and classifier-free guidance for conditioning.

- Forward process: fixed Markov chain with closed-form marginals -- no parameters to learn.
- Training: sample t ~ Uniform, corrupt x0 to xt in one step, minimize ||eps - eps_hat||^2.
- Reverse: T Gaussian steps learned by U-Net conditioned on timestep t via sinusoidal embedding.
- Beta schedule: linear (original) or cosine (improved) -- cosine better at preserving low-t signal.
- Sample quality: competitive with GANs on CIFAR-10 FID without adversarial training.
- Sampling speed: T=1000 forward passes -- the main bottleneck addressed by DDIM/DPM-Solver.

---

