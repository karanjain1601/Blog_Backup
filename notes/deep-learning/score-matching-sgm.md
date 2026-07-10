---
title: "Score Matching and Score-Based Generative Models"
slug: "score-matching-sgm"
description: "Derive the score function and score matching objectives, implement denoising score matching from scratch, build a noise-conditional score network (NCSN), run annealed Langevin dynamics, and understand the mathematical equivalence between DDPM epsilon-prediction and score estimation."
tags: ["deep-learning", "generative-models", "diffusion-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Score-based generative models train a neural network to estimate the gradient of the log data density — the score function s(x) = ∇_x log p(x). This single principle unifies denoising score matching, noise-conditional score networks (NCSN), and DDPMs. Rather than approximating p(x) directly (which requires a tractable normalizing constant Z), score models approximate ∇_x log p(x), which cancels Z. A learned score field then drives iterative sampling via Langevin dynamics or reverse-time SDEs, enabling generation without likelihood evaluation."},{"type":"heading","level":2,"content":"The Score Function"},{"type":"text","content":"For a distribution p(x) = p̃(x)/Z, the score is s(x) = ∇_x log p(x) = ∇_x log p̃(x) — Z cancels in the gradient. The score is a vector field pointing toward higher-density regions. For a Gaussian p(x) = N(μ, σ²I) the score is (μ − x)/σ², a linear restoring force toward the mean. A neural score network s_θ(x) approximates this field across the entire data distribution, enabling gradient ascent on log p without ever computing the partition function."},{"type":"heading","level":2,"content":"Explicit Score Matching (Hyvärinen 2005)"},{"type":"text","content":"Hyvärinen (2005) showed the squared-error objective E[‖s_θ(x) − ∇_x log p(x)‖²] equals E[tr(∇_x s_θ(x)) + ½‖s_θ(x)‖²] via integration by parts — no p(x) needed. The trace term tr(∇_x s_θ(x)) requires O(d) backward passes for d-dimensional inputs. At image resolution 64×64 (d=12288), this is computationally intractable. Sliced score matching (Song et al. 2020) reduces cost via random projections, but denoising score matching (DSM) provides a cleaner solution with a closed-form target."},{"type":"heading","level":2,"content":"Denoising Score Matching (Vincent 2011)"},{"type":"text","content":"Vincent (2011) proved that training on corrupted inputs is equivalent to score matching. Given x̃ = x + σε with ε ~ N(0,I), the conditional score is ∇_{x̃} log p(x̃|x) = (x − x̃)/σ² — computable without Jacobian traces. The DSM loss L = E[‖s_θ(x̃) − (x−x̃)/σ²‖²] trains the score network to predict the direction from any noisy point back toward clean data. This is precisely what DDPMs do: predicting noise ε_θ ≈ ε is equivalent to estimating the score s_θ(x̃) ≈ −ε/σ, just scaled differently."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass ScoreNet(nn.Module):\n    def __init__(self, data_dim=2, hidden=128):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(data_dim, hidden), nn.SiLU(),\n            nn.Linear(hidden, hidden), nn.SiLU(),\n            nn.Linear(hidden, data_dim)\n        )\n    def forward(self, x):\n        return self.net(x)\n\ndef dsm_loss(score_net, x, sigma=0.5):\n    \"\"\"DSM: s_theta(x_tilde) approx (x - x_tilde) / sigma^2.\"\"\"\n    noise = torch.randn_like(x) * sigma\n    x_tilde = x + noise\n    target = (x - x_tilde) / (sigma ** 2)\n    return F.mse_loss(score_net(x_tilde), target)\n\ntorch.manual_seed(42)\nnet = ScoreNet()\nopt = torch.optim.Adam(net.parameters(), lr=1e-3)\ndata = torch.cat([torch.randn(512, 2) + 2.0, torch.randn(512, 2) - 2.0])\nfor step in range(300):\n    x = data[torch.randint(len(data), (64,))]\n    loss = dsm_loss(net, x, sigma=0.4)\n    opt.zero_grad(); loss.backward(); opt.step()\n    if step % 100 == 0:\n        print(f\u0027Step {step}: DSM loss = {loss.item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Noise Conditional Score Networks (NCSN)"},{"type":"text","content":"Song \u0026 Ermon (2019) extended DSM to multiple noise levels. NCSN trains s_θ(x, σ) over a geometric sequence σ_1 \u003e ... \u003e σ_L (e.g. σ_1=1.0 to σ_L=0.01, L=10). The weighted loss Σ_l σ_l² · E[‖s_θ(x̃,σ_l) − (x−x̃)/σ_l²‖²] balances scale contributions — the σ_l² weight makes each term dimensionally uniform. Large σ guides from broad noise; small σ refines fine structure. Multi-scale training also solves the score estimation problem in low-density regions, where single-σ methods produce noisy, unreliable estimates."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\nclass NCSNScoreNet(nn.Module):\n    def __init__(self, data_dim=2, hidden=128, n_sigmas=10):\n        super().__init__()\n        self.sigma_embed = nn.Embedding(n_sigmas, 16)\n        self.net = nn.Sequential(\n            nn.Linear(data_dim + 16, hidden), nn.SiLU(),\n            nn.Linear(hidden, hidden), nn.SiLU(),\n            nn.Linear(hidden, data_dim)\n        )\n    def forward(self, x, sigma_idx):\n        emb = self.sigma_embed(sigma_idx)\n        return self.net(torch.cat([x, emb], dim=-1))\n\ndef ncsn_loss(net, x, sigmas):\n    B = x.size(0)\n    idx = torch.randint(0, len(sigmas), (B,))\n    sig = sigmas[idx].unsqueeze(1)\n    x_tilde = x + torch.randn_like(x) * sig\n    target = (x - x_tilde) / (sig ** 2)\n    pred = net(x_tilde, idx)\n    return ((sig ** 2) * (pred - target).pow(2)).mean()\n\ntorch.manual_seed(0)\nsigmas = torch.tensor(np.geomspace(1.0, 0.01, 10), dtype=torch.float32)\nncsnnet = NCSNScoreNet()\nopt = torch.optim.Adam(ncsnnet.parameters(), lr=3e-4)\ndata = torch.cat([torch.randn(500,2)*0.3+2.0, torch.randn(500,2)*0.3-2.0])\nfor step in range(400):\n    x = data[torch.randint(len(data), (128,))]\n    loss = ncsn_loss(ncsnnet, x, sigmas)\n    opt.zero_grad(); loss.backward(); opt.step()\n    if step % 100 == 0:\n        print(f\u0027Step {step}: NCSN loss = {loss.item():.5f}\u0027)"},{"type":"heading","level":2,"content":"Langevin Dynamics Sampling"},{"type":"text","content":"Annealed Langevin dynamics samples from p_data(x) using the score. Starting from x_0 ~ N(0, σ_1²I), for each level l run K steps: x_{k+1} = x_k + (α_l/2)·s_θ(x_k,σ_l) + √α_l·ε_k where α_l = ε·(σ_l/σ_L)² keeps signal-to-noise constant across levels. Under correct score estimation, the stationary distribution at each level is p_{σ_l}(x) — a smoothed version of p_data. As σ_l → 0 across L levels, the chain converges to samples from p_data(x). Typical settings: L=10 noise levels, K=100 Langevin steps per level, ε=2×10⁻⁵."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\n@torch.no_grad()\ndef annealed_langevin(score_net, sigmas, n_samples=64,\n                      data_dim=2, K=50, step_lr=2e-5):\n    \"\"\"Annealed Langevin: large sigma -\u003e small sigma, K steps each.\"\"\"\n    x = torch.randn(n_samples, data_dim) * float(sigmas[0])\n    for l, sigma in enumerate(sigmas):\n        sigma_idx = torch.full((n_samples,), l, dtype=torch.long)\n        alpha = step_lr * (float(sigma) / float(sigmas[-1])) ** 2\n        for _ in range(K):\n            score = score_net(x, sigma_idx)\n            x = x + (alpha / 2) * score + (alpha ** 0.5) * torch.randn_like(x)\n    return x\n\ntorch.manual_seed(7)\nsamples = annealed_langevin(ncsnnet, sigmas, n_samples=200, K=80)\nnear_pos = (samples[:, 0] \u003e 1.0).float().mean().item()\nnear_neg = (samples[:, 0] \u003c -1.0).float().mean().item()\nprint(f\u0027Mode coverage: +2 region={near_pos:.1%}, -2 region={near_neg:.1%}\u0027)\nprint(f\u0027Sample mean x: {samples[:,0].mean():.3f}  (expected ~0, bimodal)\u0027)\nprint(f\u0027Sample std  x: {samples[:,0].std():.3f}   (expected ~2, two modes at +-2)\u0027)"},{"type":"heading","level":2,"content":"Connection to DDPM — epsilon-Prediction as Score Estimation"},{"type":"text","content":"In DDPM, x_t = √ᾱ_t·x_0 + √(1−ᾱ_t)·ε with ε ~ N(0,I). The score of the marginal p_t(x_t) is ∇_{x_t} log p_t(x_t) = −ε/√(1−ᾱ_t). A network that predicts ε from x_t therefore implicitly estimates the score: s_θ(x_t,t) = −ε_θ(x_t,t)/√(1−ᾱ_t). The DDPM simple loss ‖ε_θ(x_t,t) − ε‖² is a DSM objective with the σ²-weighting absorbed into the noise schedule. Every trained DDPM is simultaneously a score network — no architectural change required to apply score-based samplers."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef make_alpha_bar(T=1000, beta_start=1e-4, beta_end=0.02):\n    betas = torch.linspace(beta_start, beta_end, T)\n    return torch.cumprod(1.0 - betas, dim=0)\n\ndef eps_to_score(eps_pred, t, alpha_bar):\n    \"\"\"s_theta(x_t, t) = -eps_theta(x_t, t) / sqrt(1 - alpha_bar[t])\"\"\"\n    abt = alpha_bar[t].view(-1, 1)\n    return -eps_pred / torch.sqrt(1.0 - abt)\n\ndef score_to_eps(score, t, alpha_bar):\n    abt = alpha_bar[t].view(-1, 1)\n    return -score * torch.sqrt(1.0 - abt)\n\ntorch.manual_seed(0)\nalpha_bar = make_alpha_bar(T=1000)\nB, D = 8, 16\nt = torch.randint(0, 1000, (B,))\neps = torch.randn(B, D)\nscore = eps_to_score(eps, t, alpha_bar)\neps_rt = score_to_eps(score, t, alpha_bar)\nprint(f\u0027Round-trip error: {(eps - eps_rt).abs().max():.2e}  (should be ~0)\u0027)\nprint(\u0027Score magnitude at different noise levels:\u0027)\nfor t_val in [999, 750, 500, 250, 50]:\n    tt = torch.full((1,), t_val)\n    mag = eps_to_score(torch.ones(1, D), tt, alpha_bar).norm().item()\n    print(f\u0027  t={t_val:4d}: score_norm = {mag:.4f}\u0027)"},{"type":"heading","level":2,"content":"SDE Formulation — Unifying All Diffusion Models"},{"type":"text","content":"Song et al. (2021) showed every diffusion process is a special case of a forward SDE: dx = f(x,t)dt + g(t)dW. The reverse SDE is dx = [f(x,t) − g(t)²s_θ(x,t)]dt + g(t)dW̄. DDPM uses VP-SDE (variance-preserving, linear β schedule); NCSN uses VE-SDE (variance-exploding, geometric σ sequence). Setting the diffusion term to zero gives the probability flow ODE — a deterministic sampler equivalent to DDIM. Any numerical ODE/SDE solver can be plugged in once s_θ is learned, enabling flexible speed-quality tradeoffs without retraining."},{"type":"heading","level":2,"content":"Score Matching Methods Compared"},{"type":"table","headers":["Method","Estimand","Loss form","Noise schedule","Sampling"],"rows":[["Explicit SM (Hyvärinen 2005)","∇_x log p(x)","tr(∇s_θ) + ½‖s_θ‖²  — no p(x) required","None (clean data)","Langevin dynamics"],["DSM (Vincent 2011)","(x−x̃)/σ²  — conditional score","‖s_θ(x̃) − (x−x̃)/σ²‖²  — Jacobian-free","Single fixed σ","Langevin dynamics"],["NCSN (Song \u0026 Ermon 2019)","s_θ(x,σ_l) across L levels","Weighted DSM: Σ_l σ_l²‖s_θ(x̃,l)−target‖²","Geometric σ_1\u003e…\u003eσ_L","Annealed Langevin (K steps/level)"],["DDPM (Ho et al. 2020)","ε_θ(x_t,t) ≡ −score·√(1−ᾱ_t)","Simple: ‖ε_θ(x_t,t)−ε‖²","Linear β schedule, T=1000","Ancestral sampling (T reverse steps)"]]},{"type":"callout","variant":"info","title":"Score Estimation is the Core of All Diffusion Models","content":"Every modern generative diffusion system — DDPM, latent diffusion, EDM, consistency models — learns a score network under the hood. Architectures differ (UNet, DiT, ViT) but the training signal is always denoising, which is DSM. Mastering score matching gives you a unified lens for understanding and improving any diffusion-based generator."},{"type":"list","ordered":false,"items":["Score = ∇_x log p(x): the normalizing constant Z cancels — score is computable without knowing Z.","Explicit SM requires a Jacobian trace (O(d) passes); DSM replaces it with the closed-form target (x−x̃)/σ².","NCSN trains at L noise levels; annealed Langevin sweeps coarse-to-fine, solving low-density estimation.","DDPM epsilon-prediction is score estimation in disguise: s_θ = −ε_θ / √(1−ᾱ_t).","SDE framework unifies all methods: VP-SDE (DDPM), VE-SDE (NCSN), probability flow ODE (DDIM).","Sliced score matching and denoising diffusion probabilistic models converge to the same objective."]},{"type":"divider"}]"
---
# Score Matching and Score-Based Generative Models

Score-based generative models train a neural network to estimate the gradient of the log data density — the score function s(x) = ∇_x log p(x). This single principle unifies denoising score matching, noise-conditional score networks (NCSN), and DDPMs. Rather than approximating p(x) directly (which requires a tractable normalizing constant Z), score models approximate ∇_x log p(x), which cancels Z. A learned score field then drives iterative sampling via Langevin dynamics or reverse-time SDEs, enabling generation without likelihood evaluation.

## The Score Function

For a distribution p(x) = p̃(x)/Z, the score is s(x) = ∇_x log p(x) = ∇_x log p̃(x) — Z cancels in the gradient. The score is a vector field pointing toward higher-density regions. For a Gaussian p(x) = N(μ, σ²I) the score is (μ − x)/σ², a linear restoring force toward the mean. A neural score network s_θ(x) approximates this field across the entire data distribution, enabling gradient ascent on log p without ever computing the partition function.

## Explicit Score Matching (Hyvärinen 2005)

Hyvärinen (2005) showed the squared-error objective E[‖s_θ(x) − ∇_x log p(x)‖²] equals E[tr(∇_x s_θ(x)) + ½‖s_θ(x)‖²] via integration by parts — no p(x) needed. The trace term tr(∇_x s_θ(x)) requires O(d) backward passes for d-dimensional inputs. At image resolution 64×64 (d=12288), this is computationally intractable. Sliced score matching (Song et al. 2020) reduces cost via random projections, but denoising score matching (DSM) provides a cleaner solution with a closed-form target.

## Denoising Score Matching (Vincent 2011)

Vincent (2011) proved that training on corrupted inputs is equivalent to score matching. Given x̃ = x + σε with ε ~ N(0,I), the conditional score is ∇_{x̃} log p(x̃|x) = (x − x̃)/σ² — computable without Jacobian traces. The DSM loss L = E[‖s_θ(x̃) − (x−x̃)/σ²‖²] trains the score network to predict the direction from any noisy point back toward clean data. This is precisely what DDPMs do: predicting noise ε_θ ≈ ε is equivalent to estimating the score s_θ(x̃) ≈ −ε/σ, just scaled differently.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class ScoreNet(nn.Module):
    def __init__(self, data_dim=2, hidden=128):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(data_dim, hidden), nn.SiLU(),
            nn.Linear(hidden, hidden), nn.SiLU(),
            nn.Linear(hidden, data_dim)
        )
    def forward(self, x):
        return self.net(x)

def dsm_loss(score_net, x, sigma=0.5):
    """DSM: s_theta(x_tilde) approx (x - x_tilde) / sigma^2."""
    noise = torch.randn_like(x) * sigma
    x_tilde = x + noise
    target = (x - x_tilde) / (sigma ** 2)
    return F.mse_loss(score_net(x_tilde), target)

torch.manual_seed(42)
net = ScoreNet()
opt = torch.optim.Adam(net.parameters(), lr=1e-3)
data = torch.cat([torch.randn(512, 2) + 2.0, torch.randn(512, 2) - 2.0])
for step in range(300):
    x = data[torch.randint(len(data), (64,))]
    loss = dsm_loss(net, x, sigma=0.4)
    opt.zero_grad(); loss.backward(); opt.step()
    if step % 100 == 0:
        print(f'Step {step}: DSM loss = {loss.item():.4f}')
```

## Noise Conditional Score Networks (NCSN)

Song & Ermon (2019) extended DSM to multiple noise levels. NCSN trains s_θ(x, σ) over a geometric sequence σ_1 > ... > σ_L (e.g. σ_1=1.0 to σ_L=0.01, L=10). The weighted loss Σ_l σ_l² · E[‖s_θ(x̃,σ_l) − (x−x̃)/σ_l²‖²] balances scale contributions — the σ_l² weight makes each term dimensionally uniform. Large σ guides from broad noise; small σ refines fine structure. Multi-scale training also solves the score estimation problem in low-density regions, where single-σ methods produce noisy, unreliable estimates.

```python
import torch
import torch.nn as nn
import numpy as np

class NCSNScoreNet(nn.Module):
    def __init__(self, data_dim=2, hidden=128, n_sigmas=10):
        super().__init__()
        self.sigma_embed = nn.Embedding(n_sigmas, 16)
        self.net = nn.Sequential(
            nn.Linear(data_dim + 16, hidden), nn.SiLU(),
            nn.Linear(hidden, hidden), nn.SiLU(),
            nn.Linear(hidden, data_dim)
        )
    def forward(self, x, sigma_idx):
        emb = self.sigma_embed(sigma_idx)
        return self.net(torch.cat([x, emb], dim=-1))

def ncsn_loss(net, x, sigmas):
    B = x.size(0)
    idx = torch.randint(0, len(sigmas), (B,))
    sig = sigmas[idx].unsqueeze(1)
    x_tilde = x + torch.randn_like(x) * sig
    target = (x - x_tilde) / (sig ** 2)
    pred = net(x_tilde, idx)
    return ((sig ** 2) * (pred - target).pow(2)).mean()

torch.manual_seed(0)
sigmas = torch.tensor(np.geomspace(1.0, 0.01, 10), dtype=torch.float32)
ncsnnet = NCSNScoreNet()
opt = torch.optim.Adam(ncsnnet.parameters(), lr=3e-4)
data = torch.cat([torch.randn(500,2)*0.3+2.0, torch.randn(500,2)*0.3-2.0])
for step in range(400):
    x = data[torch.randint(len(data), (128,))]
    loss = ncsn_loss(ncsnnet, x, sigmas)
    opt.zero_grad(); loss.backward(); opt.step()
    if step % 100 == 0:
        print(f'Step {step}: NCSN loss = {loss.item():.5f}')
```

## Langevin Dynamics Sampling

Annealed Langevin dynamics samples from p_data(x) using the score. Starting from x_0 ~ N(0, σ_1²I), for each level l run K steps: x_{k+1} = x_k + (α_l/2)·s_θ(x_k,σ_l) + √α_l·ε_k where α_l = ε·(σ_l/σ_L)² keeps signal-to-noise constant across levels. Under correct score estimation, the stationary distribution at each level is p_{σ_l}(x) — a smoothed version of p_data. As σ_l → 0 across L levels, the chain converges to samples from p_data(x). Typical settings: L=10 noise levels, K=100 Langevin steps per level, ε=2×10⁻⁵.

```python
import torch
import numpy as np

@torch.no_grad()
def annealed_langevin(score_net, sigmas, n_samples=64,
                      data_dim=2, K=50, step_lr=2e-5):
    """Annealed Langevin: large sigma -> small sigma, K steps each."""
    x = torch.randn(n_samples, data_dim) * float(sigmas[0])
    for l, sigma in enumerate(sigmas):
        sigma_idx = torch.full((n_samples,), l, dtype=torch.long)
        alpha = step_lr * (float(sigma) / float(sigmas[-1])) ** 2
        for _ in range(K):
            score = score_net(x, sigma_idx)
            x = x + (alpha / 2) * score + (alpha ** 0.5) * torch.randn_like(x)
    return x

torch.manual_seed(7)
samples = annealed_langevin(ncsnnet, sigmas, n_samples=200, K=80)
near_pos = (samples[:, 0] > 1.0).float().mean().item()
near_neg = (samples[:, 0] < -1.0).float().mean().item()
print(f'Mode coverage: +2 region={near_pos:.1%}, -2 region={near_neg:.1%}')
print(f'Sample mean x: {samples[:,0].mean():.3f}  (expected ~0, bimodal)')
print(f'Sample std  x: {samples[:,0].std():.3f}   (expected ~2, two modes at +-2)')
```

## Connection to DDPM — epsilon-Prediction as Score Estimation

In DDPM, x_t = √ᾱ_t·x_0 + √(1−ᾱ_t)·ε with ε ~ N(0,I). The score of the marginal p_t(x_t) is ∇_{x_t} log p_t(x_t) = −ε/√(1−ᾱ_t). A network that predicts ε from x_t therefore implicitly estimates the score: s_θ(x_t,t) = −ε_θ(x_t,t)/√(1−ᾱ_t). The DDPM simple loss ‖ε_θ(x_t,t) − ε‖² is a DSM objective with the σ²-weighting absorbed into the noise schedule. Every trained DDPM is simultaneously a score network — no architectural change required to apply score-based samplers.

```python
import torch
import numpy as np

def make_alpha_bar(T=1000, beta_start=1e-4, beta_end=0.02):
    betas = torch.linspace(beta_start, beta_end, T)
    return torch.cumprod(1.0 - betas, dim=0)

def eps_to_score(eps_pred, t, alpha_bar):
    """s_theta(x_t, t) = -eps_theta(x_t, t) / sqrt(1 - alpha_bar[t])"""
    abt = alpha_bar[t].view(-1, 1)
    return -eps_pred / torch.sqrt(1.0 - abt)

def score_to_eps(score, t, alpha_bar):
    abt = alpha_bar[t].view(-1, 1)
    return -score * torch.sqrt(1.0 - abt)

torch.manual_seed(0)
alpha_bar = make_alpha_bar(T=1000)
B, D = 8, 16
t = torch.randint(0, 1000, (B,))
eps = torch.randn(B, D)
score = eps_to_score(eps, t, alpha_bar)
eps_rt = score_to_eps(score, t, alpha_bar)
print(f'Round-trip error: {(eps - eps_rt).abs().max():.2e}  (should be ~0)')
print('Score magnitude at different noise levels:')
for t_val in [999, 750, 500, 250, 50]:
    tt = torch.full((1,), t_val)
    mag = eps_to_score(torch.ones(1, D), tt, alpha_bar).norm().item()
    print(f'  t={t_val:4d}: score_norm = {mag:.4f}')
```

## SDE Formulation — Unifying All Diffusion Models

Song et al. (2021) showed every diffusion process is a special case of a forward SDE: dx = f(x,t)dt + g(t)dW. The reverse SDE is dx = [f(x,t) − g(t)²s_θ(x,t)]dt + g(t)dW̄. DDPM uses VP-SDE (variance-preserving, linear β schedule); NCSN uses VE-SDE (variance-exploding, geometric σ sequence). Setting the diffusion term to zero gives the probability flow ODE — a deterministic sampler equivalent to DDIM. Any numerical ODE/SDE solver can be plugged in once s_θ is learned, enabling flexible speed-quality tradeoffs without retraining.

## Score Matching Methods Compared

| Method | Estimand | Loss form | Noise schedule | Sampling |
| --- | --- | --- | --- | --- |
| Explicit SM (Hyvärinen 2005) | ∇_x log p(x) | tr(∇s_θ) + ½‖s_θ‖²  — no p(x) required | None (clean data) | Langevin dynamics |
| DSM (Vincent 2011) | (x−x̃)/σ²  — conditional score | ‖s_θ(x̃) − (x−x̃)/σ²‖²  — Jacobian-free | Single fixed σ | Langevin dynamics |
| NCSN (Song & Ermon 2019) | s_θ(x,σ_l) across L levels | Weighted DSM: Σ_l σ_l²‖s_θ(x̃,l)−target‖² | Geometric σ_1>…>σ_L | Annealed Langevin (K steps/level) |
| DDPM (Ho et al. 2020) | ε_θ(x_t,t) ≡ −score·√(1−ᾱ_t) | Simple: ‖ε_θ(x_t,t)−ε‖² | Linear β schedule, T=1000 | Ancestral sampling (T reverse steps) |

> **Score Estimation is the Core of All Diffusion Models**: Every modern generative diffusion system — DDPM, latent diffusion, EDM, consistency models — learns a score network under the hood. Architectures differ (UNet, DiT, ViT) but the training signal is always denoising, which is DSM. Mastering score matching gives you a unified lens for understanding and improving any diffusion-based generator.

- Score = ∇_x log p(x): the normalizing constant Z cancels — score is computable without knowing Z.
- Explicit SM requires a Jacobian trace (O(d) passes); DSM replaces it with the closed-form target (x−x̃)/σ².
- NCSN trains at L noise levels; annealed Langevin sweeps coarse-to-fine, solving low-density estimation.
- DDPM epsilon-prediction is score estimation in disguise: s_θ = −ε_θ / √(1−ᾱ_t).
- SDE framework unifies all methods: VP-SDE (DDPM), VE-SDE (NCSN), probability flow ODE (DDIM).
- Sliced score matching and denoising diffusion probabilistic models converge to the same objective.

---

