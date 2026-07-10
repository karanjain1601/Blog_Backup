---
title: "DDPM Loss — VLB, Simplified Objective, and x₀ vs ε Prediction"
slug: "ddpm-loss-derivation"
description: "Derives the DDPM training objective from the ELBO: each KL term is a Gaussian-vs-Gaussian comparison with tractable posterior. Ho et al. simplify to predict noise epsilon. Covers x0- vs eps- vs v-prediction, SNR weighting, and min-SNR-gamma for stable training."
tags: ["deep-learning", "generative-models", "diffusion-models", "normalizing-flows"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The DDPM training objective is derived from the evidence lower bound (ELBO) on log p(x_0). Because the forward process is a fixed Markov chain with Gaussian conditionals, every term in the ELBO reduces to a KL divergence between Gaussians, which has a closed-form expression. Ho et al. further simplify by dropping reweighting and predicting noise ε instead of the mean, arriving at a standard MSE loss. Understanding the full derivation illuminates why ε-prediction works, how SNR shapes the loss landscape, and how min-SNR weighting improves training stability."},{"type":"heading","level":2,"content":"Evidence Lower Bound (VLB) for Diffusion Models"},{"type":"text","content":"The log-likelihood log p_θ(x_0) is intractable. Instead we maximize the ELBO: L = E_q[log p_θ(x_0|x_1)] - KL[q(x_T|x_0) || p(x_T)] - Σ_{t=2}^{T} E_q[KL[q(x_{t-1}|x_t, x_0) || p_θ(x_{t-1}|x_t)]]. The first term is the reconstruction loss, the second is a boundary term (fixed, since p(x_T) = N(0,I) and q(x_T|x_0) ≈ N(0,I) for large T), and the sum of KL terms is the main training signal. Each KL is between two Gaussians: the tractable posterior q(x_{t-1}|x_t, x_0) and the learned p_θ(x_{t-1}|x_t)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef kl_gaussian(mu1, log_var1, mu2, log_var2):\n    \"\"\"KL(N(mu1,exp(lv1)) || N(mu2,exp(lv2))) -- closed form.\"\"\"\n    return 0.5 * (log_var2 - log_var1\n                  + (log_var1.exp() + (mu1 - mu2)**2) / log_var2.exp() - 1)\n\ndef q_posterior(x0, xt, t, alpha_bar, beta):\n    \"\"\"Tractable posterior q(x_{t-1}|x_t,x_0): mean and log-variance.\"\"\"\n    alpha  = 1.0 - beta\n    ab_t   = alpha_bar[t]\n    ab_p   = alpha_bar[t - 1] if t \u003e 0 else torch.ones_like(ab_t)\n    c1 = ab_p.sqrt() * beta[t] / (1 - ab_t)\n    c2 = alpha[t].sqrt() * (1 - ab_p) / (1 - ab_t)\n    mu_q   = c1 * x0 + c2 * xt\n    var_q  = beta[t] * (1 - ab_p) / (1 - ab_t)\n    return mu_q, var_q.log()\n\ndef vlb_term(model, x0, t, alpha_bar, beta):\n    \"\"\"Single VLB term L_t = E[KL(q(x_{t-1}|x_t,x0) || p_theta(x_{t-1}|x_t))].\"\"\"\n    noise = torch.randn_like(x0)\n    ab_t  = alpha_bar[t]\n    xt    = ab_t.sqrt() * x0 + (1 - ab_t).sqrt() * noise\n    mu_q, lv_q = q_posterior(x0, xt, t, alpha_bar, beta)\n    t_b   = torch.full((x0.shape[0],), t, dtype=torch.long)\n    eps_p = model(xt, t_b)\n    x0_p  = (xt - (1 - ab_t).sqrt() * eps_p) / ab_t.sqrt()\n    mu_p, _ = q_posterior(x0_p.detach(), xt, t, alpha_bar, beta)\n    kl = kl_gaussian(mu_q, lv_q, mu_p, lv_q)\n    return kl.mean()\n\nprint(\"VLB = E[log p(x0|x1)] - KL[q(xT|x0)||p(xT)]\")\nprint(\"    - sum_{t=2}^{T} E[KL[q(x_{t-1}|x_t,x0) || p_theta(x_{t-1}|x_t)]]\")\nprint(\"Each KL is Gaussian-vs-Gaussian -- closed form, no MC needed\")"},{"type":"heading","level":2,"content":"Tractable Posterior q(x_{t-1} | x_t, x_0)"},{"type":"text","content":"Conditioning on x_0 makes the reverse posterior tractable. By Bayes\u0027 rule and the Markov property: q(x_{t-1} | x_t, x_0) ∝ q(x_t | x_{t-1}) q(x_{t-1} | x_0). Both factors are Gaussian, so their product is also Gaussian. The resulting posterior has mean μ̃_t = (√α̅_{t-1} β_t x_0 + √α_t (1-α̅_{t-1}) x_t) / (1-α̅_t) and variance β̃_t = β_t (1-α̅_{t-1}) / (1-α̅_t). Crucially, β̃_t depends only on the fixed schedule, not on the data. This means the KL term simplifies to a comparison of means only (the variances match), reducing each L_t to a weighted MSE between μ̃_t and μ_θ."},{"type":"heading","level":2,"content":"Simplified ε-Prediction Loss"},{"type":"text","content":"Reparameterizing μ_θ in terms of the predicted noise ε_θ: μ_θ(x_t, t) = (x_t - β_t / √(1-α̅_t) ε_θ(x_t, t)) / √α_t. Substituting into the KL, each L_t becomes proportional to ||ε - ε_θ(x_t, t)||^2 with a weight β_t² / (2α_t(1-α̅_t)). Ho et al. drop this per-timestep weight (set all weights to 1) and find that the unweighted loss: L_{simple} = E_{t,x_0,ε}[||ε - ε_θ(√α̅_t x_0 + √(1-α̅_t)ε, t)||^2] achieves better sample quality. The weight dropping implicitly up-weights high-noise timesteps (large t, small SNR) relative to the VLB."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef ddpm_loss_simple(model, x0, alpha_bar, device=\u0027cpu\u0027):\n    \"\"\"\n    Simplified DDPM loss (Ho et al. 2020, Eq. 14).\n    L_simple = E[||eps - eps_theta(sqrt(ab_t)*x0 + sqrt(1-ab_t)*eps, t)||^2]\n    Uniform weighting over t -- drops VLB weights, empirically better.\n    \"\"\"\n    B   = x0.shape[0]\n    t   = torch.randint(0, len(alpha_bar), (B,), device=device)\n    eps = torch.randn_like(x0)\n    ab  = alpha_bar[t].view(-1, 1, 1, 1)\n    xt  = ab.sqrt() * x0 + (1 - ab).sqrt() * eps\n    eps_hat = model(xt, t)\n    return F.mse_loss(eps_hat, eps)\n\nimport torch\nT         = 1000\nbeta      = torch.linspace(1e-4, 0.02, T)\nalpha_bar = torch.cumprod(1 - beta, dim=0)\nmodel     = SimpleUNet()\noptimizer = torch.optim.Adam(model.parameters(), lr=2e-4)\n\nfor step in range(3):\n    x0   = torch.randn(4, 3, 32, 32)\n    loss = ddpm_loss_simple(model, x0, alpha_bar)\n    optimizer.zero_grad()\n    loss.backward()\n    optimizer.step()\n    print(f\"Step {step}: L_simple={loss.item():.4f}\")\nprint(\"Uniform t weighting: implicitly up-weights high-noise (large t) terms\")"},{"type":"heading","level":2,"content":"x₀ vs ε vs v Prediction"},{"type":"text","content":"Three parameterizations are equivalent at infinite capacity but differ in bias and gradient scaling in practice. ε-prediction predicts the noise: target ε has unit scale, stable at high noise (large t), but at low noise (small t, high SNR) the loss is dominated by fine details. x_0-prediction predicts the clean image directly: natural at low noise, but noisy at high noise where x_0 is barely recoverable. v-prediction (Salimans \u0026 Ho, 2022) predicts v = √α̅_t ε - √(1-α̅_t) x_0, an interpolation that balances well across all noise levels. Imagen and latent diffusion models often use v-prediction for high resolution."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef loss_eps(model, x0, alpha_bar):\n    \"\"\"eps-prediction: predict the added noise.\"\"\"\n    B, t  = x0.shape[0], torch.randint(0, len(alpha_bar), (x0.shape[0],))\n    eps   = torch.randn_like(x0)\n    ab    = alpha_bar[t].view(-1, 1, 1, 1)\n    xt    = ab.sqrt() * x0 + (1 - ab).sqrt() * eps\n    return F.mse_loss(model(xt, t), eps)\n\ndef loss_x0(model, x0, alpha_bar):\n    \"\"\"x0-prediction: predict the original clean image.\"\"\"\n    B, t  = x0.shape[0], torch.randint(0, len(alpha_bar), (x0.shape[0],))\n    eps   = torch.randn_like(x0)\n    ab    = alpha_bar[t].view(-1, 1, 1, 1)\n    xt    = ab.sqrt() * x0 + (1 - ab).sqrt() * eps\n    return F.mse_loss(model(xt, t), x0)\n\ndef loss_v(model, x0, alpha_bar):\n    \"\"\"v-prediction: v = sqrt(ab_t)*eps - sqrt(1-ab_t)*x0.\"\"\"\n    B, t  = x0.shape[0], torch.randint(0, len(alpha_bar), (x0.shape[0],))\n    eps   = torch.randn_like(x0)\n    ab    = alpha_bar[t].view(-1, 1, 1, 1)\n    xt    = ab.sqrt() * x0 + (1 - ab).sqrt() * eps\n    v_tgt = ab.sqrt() * eps - (1 - ab).sqrt() * x0\n    return F.mse_loss(model(xt, t), v_tgt)\n\nT = 1000\nbeta = torch.linspace(1e-4, 0.02, T)\nalpha_bar = torch.cumprod(1 - beta, dim=0)\nmodel = SimpleUNet()\n\nfor name, fn in [(\u0027eps-pred\u0027, loss_eps), (\u0027x0-pred \u0027, loss_x0), (\u0027v-pred  \u0027, loss_v)]:\n    losses = [fn(model, torch.randn(4, 3, 32, 32), alpha_bar).item() for _ in range(4)]\n    print(f\"{name}: mean loss = {sum(losses)/len(losses):.4f}\")"},{"type":"heading","level":2,"content":"Signal-to-Noise Ratio Perspective"},{"type":"text","content":"The SNR at timestep t is SNR_t = α̅_t / (1 - α̅_t). The full VLB weights each L_t by SNR_t - SNR_{t-1} ≈ ∂SNR/∂t. Under ε-prediction, L_{simple} implicitly assigns weight 1 to all timesteps, which means high-SNR (low-noise) timesteps are under-weighted compared to the VLB and low-SNR (high-noise) timesteps are over-weighted. Under x_0-prediction, the implicit weight is proportional to SNR_t, severely up-weighting low-noise steps. The VLB and simplified losses have different empirical behavior because they put different importance on different noise levels."},{"type":"callout","variant":"info","title":"SNR Weighting in Diffusion Loss","content":"VLB weight for L_t under x_0-prediction is proportional to SNR_t, which spans many orders of magnitude: SNR at t=1 (near-clean) can be ~10,000 while SNR at t=999 (near-noise) is ~0.0001. This 10^8 dynamic range makes the VLB extremely sensitive to low-noise terms and numerically unstable. The simplified loss with uniform weights avoids this but loses the theoretical grounding of the ELBO."},{"type":"heading","level":2,"content":"Min-SNR Weighting"},{"type":"text","content":"Min-SNR-γ (Hang et al., 2023) proposes a principled compromise: weight each L_t by min(SNR_t, γ) / SNR_t. This caps the contribution of low-noise (high-SNR) timesteps to at most γ times the weight of high-noise steps. With γ=5, the loss becomes more uniform than x_0-prediction while still respecting the SNR structure. Empirically this reduces the gap between VLB and simplified objectives and stabilizes training, especially for large models."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef compute_snr(alpha_bar):\n    \"\"\"SNR_t = alpha_bar_t / (1 - alpha_bar_t).\"\"\"\n    return alpha_bar / (1.0 - alpha_bar)\n\ndef min_snr_loss(model, x0, alpha_bar, gamma=5.0):\n    \"\"\"\n    Min-SNR-gamma loss (Hang et al. 2023).\n    weight_t = min(SNR_t, gamma) / SNR_t\n    Caps influence of high-SNR (low-noise) timesteps.\n    \"\"\"\n    B   = x0.shape[0]\n    t   = torch.randint(0, len(alpha_bar), (B,))\n    eps = torch.randn_like(x0)\n    ab  = alpha_bar[t].view(-1, 1, 1, 1)\n    xt  = ab.sqrt() * x0 + (1 - ab).sqrt() * eps\n    eps_hat = model(xt, t)\n    mse  = F.mse_loss(eps_hat, eps, reduction=\u0027none\u0027).mean(dim=[1, 2, 3])\n    snr  = compute_snr(alpha_bar[t])\n    w    = torch.minimum(snr, torch.full_like(snr, gamma)) / snr\n    return (w * mse).mean()\n\nT    = 1000\nbeta = torch.linspace(1e-4, 0.02, T)\nab   = torch.cumprod(1 - beta, dim=0)\nsnr  = compute_snr(ab)\nmodel = SimpleUNet()\nx0    = torch.randn(8, 3, 32, 32)\n\nl_simple  = F.mse_loss(model(ab[500].sqrt()*x0, torch.full((8,),500,dtype=torch.long)), torch.randn_like(x0))\nl_minsnr  = min_snr_loss(model, x0, ab, gamma=5.0)\nprint(f\"Simple loss:    {l_simple.item():.4f}\")\nprint(f\"Min-SNR-5 loss: {l_minsnr.item():.4f}\")\nprint(f\"SNR range: {snr.min():.5f} (t={T-1}) to {snr.max():.1f} (t=0)\")\nprint(\"Min-SNR-5: weights capped at gamma=5 -- reduces 10^8 dynamic range\")"},{"type":"heading","level":2,"content":"Objective Comparison"},{"type":"table","headers":["Objective","Network output","Implicit weight","High-noise behavior","Low-noise behavior","Used in"],"rows":[["Full VLB (eps-pred)","Noise eps","SNR_t - SNR_{t-1}","Accurate, high variance","Accurate, high weight","DDPM theoretical analysis"],["L_simple (eps-pred)","Noise eps","Uniform (1 per t)","Stable unit-scale targets","Under-weighted vs VLB","DDPM, DDPM++, most models"],["x0-prediction","Clean image x0","Proportional to SNR_t","Noisy -- low SNR makes x0 hard","Natural and stable","Some improved DDPMs"],["v-prediction","v = sqrt(ab) eps - sqrt(1-ab) x0","Balanced across SNR","Handles well (v ~ eps)","Handles well (v ~ -x0)","Imagen, latent diffusion"],["Min-SNR-gamma","Noise eps","min(SNR_t, gamma)/SNR_t","Similar to simple","Capped contribution","SD3, improved training"]]},{"type":"text","content":"The choice of prediction target and loss weighting significantly affects training dynamics, final sample quality, and the difficulty of the optimization landscape. ε-prediction with L_{simple} is the dominant choice for its simplicity and empirical performance. v-prediction is preferred for high-resolution synthesis and cascaded diffusion models where SNR spans a very wide range. Min-SNR weighting is a drop-in improvement applicable to any prediction target."},{"type":"list","ordered":false,"items":["VLB: principled ELBO with per-t weights -- theoretically grounded but high variance in practice.","L_simple: drop VLB weights, uniform weighting -- simpler and empirically better (Ho et al.).","eps vs x0: mathematically equivalent, differ in implicit SNR weighting and training stability.","v-prediction: interpolates eps and x0, balanced at all noise levels, preferred for high-res.","Min-SNR-gamma: caps SNR weight at gamma -- reduces 10^8 dynamic range to O(gamma) range.","Key insight: the choice of parameterization encodes an implicit prior on which noise levels matter most."]},{"type":"divider"}]"
---
# DDPM Loss — VLB, Simplified Objective, and x₀ vs ε Prediction

The DDPM training objective is derived from the evidence lower bound (ELBO) on log p(x_0). Because the forward process is a fixed Markov chain with Gaussian conditionals, every term in the ELBO reduces to a KL divergence between Gaussians, which has a closed-form expression. Ho et al. further simplify by dropping reweighting and predicting noise ε instead of the mean, arriving at a standard MSE loss. Understanding the full derivation illuminates why ε-prediction works, how SNR shapes the loss landscape, and how min-SNR weighting improves training stability.

## Evidence Lower Bound (VLB) for Diffusion Models

The log-likelihood log p_θ(x_0) is intractable. Instead we maximize the ELBO: L = E_q[log p_θ(x_0|x_1)] - KL[q(x_T|x_0) || p(x_T)] - Σ_{t=2}^{T} E_q[KL[q(x_{t-1}|x_t, x_0) || p_θ(x_{t-1}|x_t)]]. The first term is the reconstruction loss, the second is a boundary term (fixed, since p(x_T) = N(0,I) and q(x_T|x_0) ≈ N(0,I) for large T), and the sum of KL terms is the main training signal. Each KL is between two Gaussians: the tractable posterior q(x_{t-1}|x_t, x_0) and the learned p_θ(x_{t-1}|x_t).

```python
import torch
import torch.nn as nn

def kl_gaussian(mu1, log_var1, mu2, log_var2):
    """KL(N(mu1,exp(lv1)) || N(mu2,exp(lv2))) -- closed form."""
    return 0.5 * (log_var2 - log_var1
                  + (log_var1.exp() + (mu1 - mu2)**2) / log_var2.exp() - 1)

def q_posterior(x0, xt, t, alpha_bar, beta):
    """Tractable posterior q(x_{t-1}|x_t,x_0): mean and log-variance."""
    alpha  = 1.0 - beta
    ab_t   = alpha_bar[t]
    ab_p   = alpha_bar[t - 1] if t > 0 else torch.ones_like(ab_t)
    c1 = ab_p.sqrt() * beta[t] / (1 - ab_t)
    c2 = alpha[t].sqrt() * (1 - ab_p) / (1 - ab_t)
    mu_q   = c1 * x0 + c2 * xt
    var_q  = beta[t] * (1 - ab_p) / (1 - ab_t)
    return mu_q, var_q.log()

def vlb_term(model, x0, t, alpha_bar, beta):
    """Single VLB term L_t = E[KL(q(x_{t-1}|x_t,x0) || p_theta(x_{t-1}|x_t))]."""
    noise = torch.randn_like(x0)
    ab_t  = alpha_bar[t]
    xt    = ab_t.sqrt() * x0 + (1 - ab_t).sqrt() * noise
    mu_q, lv_q = q_posterior(x0, xt, t, alpha_bar, beta)
    t_b   = torch.full((x0.shape[0],), t, dtype=torch.long)
    eps_p = model(xt, t_b)
    x0_p  = (xt - (1 - ab_t).sqrt() * eps_p) / ab_t.sqrt()
    mu_p, _ = q_posterior(x0_p.detach(), xt, t, alpha_bar, beta)
    kl = kl_gaussian(mu_q, lv_q, mu_p, lv_q)
    return kl.mean()

print("VLB = E[log p(x0|x1)] - KL[q(xT|x0)||p(xT)]")
print("    - sum_{t=2}^{T} E[KL[q(x_{t-1}|x_t,x0) || p_theta(x_{t-1}|x_t)]]")
print("Each KL is Gaussian-vs-Gaussian -- closed form, no MC needed")
```

## Tractable Posterior q(x_{t-1} | x_t, x_0)

Conditioning on x_0 makes the reverse posterior tractable. By Bayes' rule and the Markov property: q(x_{t-1} | x_t, x_0) ∝ q(x_t | x_{t-1}) q(x_{t-1} | x_0). Both factors are Gaussian, so their product is also Gaussian. The resulting posterior has mean μ̃_t = (√α̅_{t-1} β_t x_0 + √α_t (1-α̅_{t-1}) x_t) / (1-α̅_t) and variance β̃_t = β_t (1-α̅_{t-1}) / (1-α̅_t). Crucially, β̃_t depends only on the fixed schedule, not on the data. This means the KL term simplifies to a comparison of means only (the variances match), reducing each L_t to a weighted MSE between μ̃_t and μ_θ.

## Simplified ε-Prediction Loss

Reparameterizing μ_θ in terms of the predicted noise ε_θ: μ_θ(x_t, t) = (x_t - β_t / √(1-α̅_t) ε_θ(x_t, t)) / √α_t. Substituting into the KL, each L_t becomes proportional to ||ε - ε_θ(x_t, t)||^2 with a weight β_t² / (2α_t(1-α̅_t)). Ho et al. drop this per-timestep weight (set all weights to 1) and find that the unweighted loss: L_{simple} = E_{t,x_0,ε}[||ε - ε_θ(√α̅_t x_0 + √(1-α̅_t)ε, t)||^2] achieves better sample quality. The weight dropping implicitly up-weights high-noise timesteps (large t, small SNR) relative to the VLB.

```python
import torch
import torch.nn.functional as F

def ddpm_loss_simple(model, x0, alpha_bar, device='cpu'):
    """
    Simplified DDPM loss (Ho et al. 2020, Eq. 14).
    L_simple = E[||eps - eps_theta(sqrt(ab_t)*x0 + sqrt(1-ab_t)*eps, t)||^2]
    Uniform weighting over t -- drops VLB weights, empirically better.
    """
    B   = x0.shape[0]
    t   = torch.randint(0, len(alpha_bar), (B,), device=device)
    eps = torch.randn_like(x0)
    ab  = alpha_bar[t].view(-1, 1, 1, 1)
    xt  = ab.sqrt() * x0 + (1 - ab).sqrt() * eps
    eps_hat = model(xt, t)
    return F.mse_loss(eps_hat, eps)

import torch
T         = 1000
beta      = torch.linspace(1e-4, 0.02, T)
alpha_bar = torch.cumprod(1 - beta, dim=0)
model     = SimpleUNet()
optimizer = torch.optim.Adam(model.parameters(), lr=2e-4)

for step in range(3):
    x0   = torch.randn(4, 3, 32, 32)
    loss = ddpm_loss_simple(model, x0, alpha_bar)
    optimizer.zero_grad()
    loss.backward()
    optimizer.step()
    print(f"Step {step}: L_simple={loss.item():.4f}")
print("Uniform t weighting: implicitly up-weights high-noise (large t) terms")
```

## x₀ vs ε vs v Prediction

Three parameterizations are equivalent at infinite capacity but differ in bias and gradient scaling in practice. ε-prediction predicts the noise: target ε has unit scale, stable at high noise (large t), but at low noise (small t, high SNR) the loss is dominated by fine details. x_0-prediction predicts the clean image directly: natural at low noise, but noisy at high noise where x_0 is barely recoverable. v-prediction (Salimans & Ho, 2022) predicts v = √α̅_t ε - √(1-α̅_t) x_0, an interpolation that balances well across all noise levels. Imagen and latent diffusion models often use v-prediction for high resolution.

```python
import torch
import torch.nn.functional as F

def loss_eps(model, x0, alpha_bar):
    """eps-prediction: predict the added noise."""
    B, t  = x0.shape[0], torch.randint(0, len(alpha_bar), (x0.shape[0],))
    eps   = torch.randn_like(x0)
    ab    = alpha_bar[t].view(-1, 1, 1, 1)
    xt    = ab.sqrt() * x0 + (1 - ab).sqrt() * eps
    return F.mse_loss(model(xt, t), eps)

def loss_x0(model, x0, alpha_bar):
    """x0-prediction: predict the original clean image."""
    B, t  = x0.shape[0], torch.randint(0, len(alpha_bar), (x0.shape[0],))
    eps   = torch.randn_like(x0)
    ab    = alpha_bar[t].view(-1, 1, 1, 1)
    xt    = ab.sqrt() * x0 + (1 - ab).sqrt() * eps
    return F.mse_loss(model(xt, t), x0)

def loss_v(model, x0, alpha_bar):
    """v-prediction: v = sqrt(ab_t)*eps - sqrt(1-ab_t)*x0."""
    B, t  = x0.shape[0], torch.randint(0, len(alpha_bar), (x0.shape[0],))
    eps   = torch.randn_like(x0)
    ab    = alpha_bar[t].view(-1, 1, 1, 1)
    xt    = ab.sqrt() * x0 + (1 - ab).sqrt() * eps
    v_tgt = ab.sqrt() * eps - (1 - ab).sqrt() * x0
    return F.mse_loss(model(xt, t), v_tgt)

T = 1000
beta = torch.linspace(1e-4, 0.02, T)
alpha_bar = torch.cumprod(1 - beta, dim=0)
model = SimpleUNet()

for name, fn in [('eps-pred', loss_eps), ('x0-pred ', loss_x0), ('v-pred  ', loss_v)]:
    losses = [fn(model, torch.randn(4, 3, 32, 32), alpha_bar).item() for _ in range(4)]
    print(f"{name}: mean loss = {sum(losses)/len(losses):.4f}")
```

## Signal-to-Noise Ratio Perspective

The SNR at timestep t is SNR_t = α̅_t / (1 - α̅_t). The full VLB weights each L_t by SNR_t - SNR_{t-1} ≈ ∂SNR/∂t. Under ε-prediction, L_{simple} implicitly assigns weight 1 to all timesteps, which means high-SNR (low-noise) timesteps are under-weighted compared to the VLB and low-SNR (high-noise) timesteps are over-weighted. Under x_0-prediction, the implicit weight is proportional to SNR_t, severely up-weighting low-noise steps. The VLB and simplified losses have different empirical behavior because they put different importance on different noise levels.

> **SNR Weighting in Diffusion Loss**: VLB weight for L_t under x_0-prediction is proportional to SNR_t, which spans many orders of magnitude: SNR at t=1 (near-clean) can be ~10,000 while SNR at t=999 (near-noise) is ~0.0001. This 10^8 dynamic range makes the VLB extremely sensitive to low-noise terms and numerically unstable. The simplified loss with uniform weights avoids this but loses the theoretical grounding of the ELBO.

## Min-SNR Weighting

Min-SNR-γ (Hang et al., 2023) proposes a principled compromise: weight each L_t by min(SNR_t, γ) / SNR_t. This caps the contribution of low-noise (high-SNR) timesteps to at most γ times the weight of high-noise steps. With γ=5, the loss becomes more uniform than x_0-prediction while still respecting the SNR structure. Empirically this reduces the gap between VLB and simplified objectives and stabilizes training, especially for large models.

```python
import torch
import torch.nn.functional as F

def compute_snr(alpha_bar):
    """SNR_t = alpha_bar_t / (1 - alpha_bar_t)."""
    return alpha_bar / (1.0 - alpha_bar)

def min_snr_loss(model, x0, alpha_bar, gamma=5.0):
    """
    Min-SNR-gamma loss (Hang et al. 2023).
    weight_t = min(SNR_t, gamma) / SNR_t
    Caps influence of high-SNR (low-noise) timesteps.
    """
    B   = x0.shape[0]
    t   = torch.randint(0, len(alpha_bar), (B,))
    eps = torch.randn_like(x0)
    ab  = alpha_bar[t].view(-1, 1, 1, 1)
    xt  = ab.sqrt() * x0 + (1 - ab).sqrt() * eps
    eps_hat = model(xt, t)
    mse  = F.mse_loss(eps_hat, eps, reduction='none').mean(dim=[1, 2, 3])
    snr  = compute_snr(alpha_bar[t])
    w    = torch.minimum(snr, torch.full_like(snr, gamma)) / snr
    return (w * mse).mean()

T    = 1000
beta = torch.linspace(1e-4, 0.02, T)
ab   = torch.cumprod(1 - beta, dim=0)
snr  = compute_snr(ab)
model = SimpleUNet()
x0    = torch.randn(8, 3, 32, 32)

l_simple  = F.mse_loss(model(ab[500].sqrt()*x0, torch.full((8,),500,dtype=torch.long)), torch.randn_like(x0))
l_minsnr  = min_snr_loss(model, x0, ab, gamma=5.0)
print(f"Simple loss:    {l_simple.item():.4f}")
print(f"Min-SNR-5 loss: {l_minsnr.item():.4f}")
print(f"SNR range: {snr.min():.5f} (t={T-1}) to {snr.max():.1f} (t=0)")
print("Min-SNR-5: weights capped at gamma=5 -- reduces 10^8 dynamic range")
```

## Objective Comparison

| Objective | Network output | Implicit weight | High-noise behavior | Low-noise behavior | Used in |
| --- | --- | --- | --- | --- | --- |
| Full VLB (eps-pred) | Noise eps | SNR_t - SNR_{t-1} | Accurate, high variance | Accurate, high weight | DDPM theoretical analysis |
| L_simple (eps-pred) | Noise eps | Uniform (1 per t) | Stable unit-scale targets | Under-weighted vs VLB | DDPM, DDPM++, most models |
| x0-prediction | Clean image x0 | Proportional to SNR_t | Noisy -- low SNR makes x0 hard | Natural and stable | Some improved DDPMs |
| v-prediction | v = sqrt(ab) eps - sqrt(1-ab) x0 | Balanced across SNR | Handles well (v ~ eps) | Handles well (v ~ -x0) | Imagen, latent diffusion |
| Min-SNR-gamma | Noise eps | min(SNR_t, gamma)/SNR_t | Similar to simple | Capped contribution | SD3, improved training |

The choice of prediction target and loss weighting significantly affects training dynamics, final sample quality, and the difficulty of the optimization landscape. ε-prediction with L_{simple} is the dominant choice for its simplicity and empirical performance. v-prediction is preferred for high-resolution synthesis and cascaded diffusion models where SNR spans a very wide range. Min-SNR weighting is a drop-in improvement applicable to any prediction target.

- VLB: principled ELBO with per-t weights -- theoretically grounded but high variance in practice.
- L_simple: drop VLB weights, uniform weighting -- simpler and empirically better (Ho et al.).
- eps vs x0: mathematically equivalent, differ in implicit SNR weighting and training stability.
- v-prediction: interpolates eps and x0, balanced at all noise levels, preferred for high-res.
- Min-SNR-gamma: caps SNR weight at gamma -- reduces 10^8 dynamic range to O(gamma) range.
- Key insight: the choice of parameterization encodes an implicit prior on which noise levels matter most.

---

