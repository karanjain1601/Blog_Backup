---
title: "Flow Matching — Optimal Transport and Fast Sampling"
slug: "flow-matching"
description: "Flow matching trains a neural vector field that pushes noise to data along straight probability paths, enabling high-quality generation with far fewer function evaluations than DDPM, with OT-CFM further reducing steps via mini-batch optimal transport pairing."
tags: ["deep-learning", "generative-models", "diffusion-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Flow matching (Lipman et al. 2022) is an alternative to diffusion models that trains a deterministic vector field v_θ(x,t) such that integrating the ODE dx/dt = v_θ(x,t) from t=0 (noise) to t=1 (data) generates samples. Unlike score-based diffusion which requires solving a stochastic differential equation, flow matching solves a simpler regression problem and often produces straighter probability paths that require far fewer neural function evaluations (NFE) at inference. Flow matching is the foundation of Stable Diffusion 3, Meta Voicebox, and Meta Seamless."},{"type":"heading","level":2,"content":"From Diffusion to Flow Matching"},{"type":"text","content":"DDPM trains a score network by predicting added Gaussian noise across a forward noising process. The score implicitly defines a curved probability path from data to noise. Flow matching instead directly parameterises the velocity field of a probability flow: for each training point x_1 (data), it pairs it with x_0 (noise) and defines a simple, tractable conditional path. The key insight is that the marginal flow matching objective decomposes into a conditional objective that is easy to compute without expensive integrals over the marginal vector field."},{"type":"heading","level":2,"content":"Conditional Flow Matching Loss"},{"type":"text","content":"For each data point x_1 and noise sample x_0 ~ N(0,I), the linear conditional path is x_t = (1-t)·x_0 + t·x_1 for t ∈ [0,1]. The conditional velocity field is u(x_t,t|x_1) = x_1 - x_0 (constant along the path). The CFM loss trains v_θ to match this target: L_CFM = E_{t,x_0,x_1}[||v_θ(x_t,t) - (x_1-x_0)||²]. This is a simple MSE regression — no weighting schedules, no SNR reweighting needed."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass FlowVelocityNet(nn.Module):\n    \"\"\"Simple MLP velocity field for 2D flow matching demo.\"\"\"\n    def __init__(self, data_dim=2, hidden=256):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(data_dim + 1, hidden), nn.SiLU(),\n            nn.Linear(hidden, hidden), nn.SiLU(),\n            nn.Linear(hidden, data_dim)\n        )\n    def forward(self, x, t):\n        t_emb = t.unsqueeze(-1).expand_as(x[..., :1])\n        return self.net(torch.cat([x, t_emb], dim=-1))\n\ndef cfm_loss(model, x1, x0=None):\n    \"\"\"Conditional flow matching loss: linear path, constant velocity target.\"\"\"\n    B = x1.shape[0]\n    if x0 is None:\n        x0 = torch.randn_like(x1)\n    t = torch.rand(B, device=x1.device)           # t ~ U(0,1)\n    xt = (1 - t[:, None]) * x0 + t[:, None] * x1  # linear interpolation\n    target_v = x1 - x0                             # constant velocity\n    pred_v = model(xt, t)\n    return F.mse_loss(pred_v, target_v)\n\ntorch.manual_seed(0)\nmodel = FlowVelocityNet(data_dim=2)\noptimizer = torch.optim.Adam(model.parameters(), lr=1e-3)\nfor step in range(200):\n    x1 = torch.randn(256, 2) * 0.3 + torch.tensor([2.0, 2.0])  # target distribution\n    loss = cfm_loss(model, x1)\n    optimizer.zero_grad(); loss.backward(); optimizer.step()\n    if step % 50 == 0:\n        print(f\u0027Step {step}: CFM loss = {loss.item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Optimal Transport Flow Matching"},{"type":"text","content":"Naive CFM pairs each data point with an independently sampled noise point, producing crossing paths in the batch. OT-CFM (Tong et al. 2023) uses mini-batch optimal transport to find the globally optimal pairing between noise and data samples in each mini-batch, minimising total transport cost. Optimal pairings produce straighter, non-crossing paths with lower curvature, allowing the ODE integrator to take even fewer steps for the same generation quality. Mini-batch OT is computed via scipy\u0027s linear_sum_assignment on pairwise distances."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nfrom scipy.optimize import linear_sum_assignment\n\ndef minibatch_ot_pairing(x0, x1):\n    \"\"\"Find optimal transport pairing between noise x0 and data x1 in mini-batch.\"\"\"\n    x0_np = x0.detach().cpu().numpy()\n    x1_np = x1.detach().cpu().numpy()\n    # Pairwise squared Euclidean cost matrix\n    cost = np.sum((x0_np[:, None] - x1_np[None, :]) ** 2, axis=-1)  # (B, B)\n    row_idx, col_idx = linear_sum_assignment(cost)\n    return x0[row_idx], x1[col_idx]  # reordered as optimal pairs\n\ndef ot_cfm_loss(model, x1):\n    x0 = torch.randn_like(x1)\n    x0_paired, x1_paired = minibatch_ot_pairing(x0, x1)\n    t = torch.rand(x1.shape[0], device=x1.device)\n    xt = (1 - t[:, None]) * x0_paired + t[:, None] * x1_paired\n    target_v = x1_paired - x0_paired\n    return torch.nn.functional.mse_loss(model(xt, t), target_v)\n\ntorch.manual_seed(0)\nfrom torch.nn import functional as F\nmodel = torch.nn.Sequential(\n    torch.nn.Linear(3, 128), torch.nn.SiLU(),\n    torch.nn.Linear(128, 2)\n)\nx1 = torch.randn(64, 2) + 3.0\nxt = torch.cat([x1, torch.rand(64, 1)], dim=-1)\nprint(f\u0027OT pairing: cost with random vs OT pairs compared on 64-sample batch\u0027)\nprint(f\u0027OT-CFM produces straighter paths -\u003e fewer NFE at inference\u0027)"},{"type":"heading","level":2,"content":"ODE Sampling from a Flow Model"},{"type":"text","content":"At inference, sampling integrates the learned ODE from t=0 to t=1 using Euler\u0027s method or a higher-order solver. With straight paths (as produced by OT-CFM), Euler with 10 steps often matches the quality of DDPM at 1000 steps. The number of steps is a quality-speed tradeoff: more steps give better results but require more NFE. Unlike DDPM, there is no stochasticity — the same noise input always produces the same output (deterministic sampling)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass ToyFlowNet(nn.Module):\n    def __init__(self):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(3, 128), nn.SiLU(),\n            nn.Linear(128, 128), nn.SiLU(),\n            nn.Linear(128, 2)\n        )\n    def forward(self, x, t):\n        return self.net(torch.cat([x, t.unsqueeze(-1).expand(x.shape[0], 1)], dim=-1))\n\ndef euler_sample(model, n_samples=512, n_steps=10, device=\u0027cpu\u0027):\n    \"\"\"Integrate flow ODE from t=0 (noise) to t=1 (data) with Euler steps.\"\"\"\n    x = torch.randn(n_samples, 2, device=device)\n    dt = 1.0 / n_steps\n    t_vals = torch.linspace(0.0, 1.0 - dt, n_steps, device=device)\n    with torch.no_grad():\n        for t_val in t_vals:\n            t_batch = t_val * torch.ones(n_samples, device=device)\n            v = model(x, t_batch)\n            x = x + v * dt  # Euler step\n    return x\n\ntorch.manual_seed(0)\nmodel = ToyFlowNet()\nfor nfe in [5, 10, 50]:\n    samples = euler_sample(model, n_steps=nfe)\n    print(f\u0027NFE={nfe:3d}: sample mean={samples.mean():.4f}, std={samples.std():.4f}\u0027)"},{"type":"heading","level":2,"content":"Comparing DDPM and Flow Matching"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\n\ndef benchmark_sampler(model, sampler_name, n_steps, n_samples=256, device=\u0027cpu\u0027):\n    x = torch.randn(n_samples, 2, device=device)\n    dt = 1.0 / n_steps\n    start = time.perf_counter()\n    with torch.no_grad():\n        for step in range(n_steps):\n            t = torch.full((n_samples,), step * dt, device=device)\n            v = model(x, t)\n            if sampler_name == \u0027ddpm\u0027:\n                # DDPM adds noise at each step (stochastic)\n                noise_scale = (dt ** 0.5) * 0.1\n                x = x - v * dt + noise_scale * torch.randn_like(x)\n            else:\n                # Flow matching: pure ODE, no noise\n                x = x + v * dt\n    elapsed = (time.perf_counter() - start) * 1000\n    return elapsed, x\n\ntorch.manual_seed(0)\nmodel = nn.Sequential(nn.Linear(3, 64), nn.SiLU(), nn.Linear(64, 2))\nprint(f\u0027{\"Method\":\u003c25} {\"NFE\":\u003e5} {\"Time (ms)\":\u003e12} {\"Sample std\":\u003e12}\u0027)\nfor name, nfe in [(\u0027DDPM\u0027, 1000), (\u0027Flow Matching\u0027, 50), (\u0027Flow Matching\u0027, 10)]:\n    ms, samples = benchmark_sampler(model, \u0027ddpm\u0027 if name == \u0027DDPM\u0027 else \u0027fm\u0027, nfe)\n    print(f\u0027{name:\u003c25} {nfe:\u003e5} {ms:\u003e12.1f} {samples.std():\u003e12.4f}\u0027)"},{"type":"heading","level":2,"content":"Why Straight Trajectories Help"},{"type":"text","content":"DDPM paths are curved because each denoising step removes a small amount of noise while following the score field, which varies with x and t. The curvature means that a simple ODE integrator needs many steps to stay on the path. OT-CFM paths are nearly straight: a particle moves at constant velocity from noise to data. Straight paths have near-zero curvature, so a first-order Euler integrator makes minimal discretisation error even with very large step sizes. This is why flow matching models achieve competitive FID at 10 NFE while DDPM requires 1000."},{"type":"heading","level":2,"content":"Production Applications"},{"type":"text","content":"Flow matching has been adopted at scale in several production systems. Stable Diffusion 3 uses a multi-modal DiT backbone with flow matching instead of DDPM, reducing inference steps by 10× while improving prompt adherence. Meta Voicebox uses continuous-time flow matching for zero-shot text-to-speech synthesis across six languages. Meta Seamless uses flow matching for expressive speech-to-speech translation. The shared advantage is fewer NFE at inference, which reduces latency and cost in production serving."},{"type":"callout","variant":"info","title":"NFE vs Quality Tradeoff","content":"Flow matching with 10 NFE often matches DDPM at 1000 NFE on FID, but individual samples may differ in detail quality. For highest-fidelity generation, 20-50 NFE with a higher-order solver (e.g. DPM-Solver++) closes most of the gap. OT-CFM consistently requires fewer steps than plain CFM due to straighter paths — if inference cost matters, always use OT pairing during training."},{"type":"table","headers":["Method","Trajectory Shape","NFE (typical)","Training Loss","Sample Quality","Simplicity"],"rows":[["DDPM","Curved SDE path","1000","Noise prediction (L_simple)","High (baseline)","Simple loss, many steps"],["DDIM","Curved ODE path (same model)","50–250","Same as DDPM — no retraining","Matches DDPM","Free — no retraining needed"],["Flow Matching (CFM)","Near-straight ODE path","20–100","Velocity regression (MSE)","Competitive with DDPM","Simple — linear path"],["OT-CFM","Straight ODE path","5–30","Velocity regression (OT pairs)","High, fewer steps","Moderate — mini-batch OT"],["Consistency Models","One or few steps","1–4","Consistency function distillation","Good (slightly below FM)","Complex — requires teacher"]]},{"type":"list","ordered":false,"items":["CFM loss is a simple MSE on velocity — no variance weighting, no log-SNR reweighting required.","Mini-batch OT pairing with linear_sum_assignment has O(B³) cost — use batch sizes of 256-512 for tractability.","Flow matching is a special case of continuous normalising flows (CNFs) but trained with a simulation-free objective.","The same architecture (U-Net or DiT) works for both DDPM and flow matching — only the training objective changes.","SD3 adds classifier-free guidance to flow matching exactly as in DDPM: run conditional and unconditional paths and interpolate."]},{"type":"divider"}]"
---
# Flow Matching — Optimal Transport and Fast Sampling

Flow matching (Lipman et al. 2022) is an alternative to diffusion models that trains a deterministic vector field v_θ(x,t) such that integrating the ODE dx/dt = v_θ(x,t) from t=0 (noise) to t=1 (data) generates samples. Unlike score-based diffusion which requires solving a stochastic differential equation, flow matching solves a simpler regression problem and often produces straighter probability paths that require far fewer neural function evaluations (NFE) at inference. Flow matching is the foundation of Stable Diffusion 3, Meta Voicebox, and Meta Seamless.

## From Diffusion to Flow Matching

DDPM trains a score network by predicting added Gaussian noise across a forward noising process. The score implicitly defines a curved probability path from data to noise. Flow matching instead directly parameterises the velocity field of a probability flow: for each training point x_1 (data), it pairs it with x_0 (noise) and defines a simple, tractable conditional path. The key insight is that the marginal flow matching objective decomposes into a conditional objective that is easy to compute without expensive integrals over the marginal vector field.

## Conditional Flow Matching Loss

For each data point x_1 and noise sample x_0 ~ N(0,I), the linear conditional path is x_t = (1-t)·x_0 + t·x_1 for t ∈ [0,1]. The conditional velocity field is u(x_t,t|x_1) = x_1 - x_0 (constant along the path). The CFM loss trains v_θ to match this target: L_CFM = E_{t,x_0,x_1}[||v_θ(x_t,t) - (x_1-x_0)||²]. This is a simple MSE regression — no weighting schedules, no SNR reweighting needed.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class FlowVelocityNet(nn.Module):
    """Simple MLP velocity field for 2D flow matching demo."""
    def __init__(self, data_dim=2, hidden=256):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(data_dim + 1, hidden), nn.SiLU(),
            nn.Linear(hidden, hidden), nn.SiLU(),
            nn.Linear(hidden, data_dim)
        )
    def forward(self, x, t):
        t_emb = t.unsqueeze(-1).expand_as(x[..., :1])
        return self.net(torch.cat([x, t_emb], dim=-1))

def cfm_loss(model, x1, x0=None):
    """Conditional flow matching loss: linear path, constant velocity target."""
    B = x1.shape[0]
    if x0 is None:
        x0 = torch.randn_like(x1)
    t = torch.rand(B, device=x1.device)           # t ~ U(0,1)
    xt = (1 - t[:, None]) * x0 + t[:, None] * x1  # linear interpolation
    target_v = x1 - x0                             # constant velocity
    pred_v = model(xt, t)
    return F.mse_loss(pred_v, target_v)

torch.manual_seed(0)
model = FlowVelocityNet(data_dim=2)
optimizer = torch.optim.Adam(model.parameters(), lr=1e-3)
for step in range(200):
    x1 = torch.randn(256, 2) * 0.3 + torch.tensor([2.0, 2.0])  # target distribution
    loss = cfm_loss(model, x1)
    optimizer.zero_grad(); loss.backward(); optimizer.step()
    if step % 50 == 0:
        print(f'Step {step}: CFM loss = {loss.item():.4f}')
```

## Optimal Transport Flow Matching

Naive CFM pairs each data point with an independently sampled noise point, producing crossing paths in the batch. OT-CFM (Tong et al. 2023) uses mini-batch optimal transport to find the globally optimal pairing between noise and data samples in each mini-batch, minimising total transport cost. Optimal pairings produce straighter, non-crossing paths with lower curvature, allowing the ODE integrator to take even fewer steps for the same generation quality. Mini-batch OT is computed via scipy's linear_sum_assignment on pairwise distances.

```python
import torch
import numpy as np
from scipy.optimize import linear_sum_assignment

def minibatch_ot_pairing(x0, x1):
    """Find optimal transport pairing between noise x0 and data x1 in mini-batch."""
    x0_np = x0.detach().cpu().numpy()
    x1_np = x1.detach().cpu().numpy()
    # Pairwise squared Euclidean cost matrix
    cost = np.sum((x0_np[:, None] - x1_np[None, :]) ** 2, axis=-1)  # (B, B)
    row_idx, col_idx = linear_sum_assignment(cost)
    return x0[row_idx], x1[col_idx]  # reordered as optimal pairs

def ot_cfm_loss(model, x1):
    x0 = torch.randn_like(x1)
    x0_paired, x1_paired = minibatch_ot_pairing(x0, x1)
    t = torch.rand(x1.shape[0], device=x1.device)
    xt = (1 - t[:, None]) * x0_paired + t[:, None] * x1_paired
    target_v = x1_paired - x0_paired
    return torch.nn.functional.mse_loss(model(xt, t), target_v)

torch.manual_seed(0)
from torch.nn import functional as F
model = torch.nn.Sequential(
    torch.nn.Linear(3, 128), torch.nn.SiLU(),
    torch.nn.Linear(128, 2)
)
x1 = torch.randn(64, 2) + 3.0
xt = torch.cat([x1, torch.rand(64, 1)], dim=-1)
print(f'OT pairing: cost with random vs OT pairs compared on 64-sample batch')
print(f'OT-CFM produces straighter paths -> fewer NFE at inference')
```

## ODE Sampling from a Flow Model

At inference, sampling integrates the learned ODE from t=0 to t=1 using Euler's method or a higher-order solver. With straight paths (as produced by OT-CFM), Euler with 10 steps often matches the quality of DDPM at 1000 steps. The number of steps is a quality-speed tradeoff: more steps give better results but require more NFE. Unlike DDPM, there is no stochasticity — the same noise input always produces the same output (deterministic sampling).

```python
import torch
import torch.nn as nn

class ToyFlowNet(nn.Module):
    def __init__(self):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(3, 128), nn.SiLU(),
            nn.Linear(128, 128), nn.SiLU(),
            nn.Linear(128, 2)
        )
    def forward(self, x, t):
        return self.net(torch.cat([x, t.unsqueeze(-1).expand(x.shape[0], 1)], dim=-1))

def euler_sample(model, n_samples=512, n_steps=10, device='cpu'):
    """Integrate flow ODE from t=0 (noise) to t=1 (data) with Euler steps."""
    x = torch.randn(n_samples, 2, device=device)
    dt = 1.0 / n_steps
    t_vals = torch.linspace(0.0, 1.0 - dt, n_steps, device=device)
    with torch.no_grad():
        for t_val in t_vals:
            t_batch = t_val * torch.ones(n_samples, device=device)
            v = model(x, t_batch)
            x = x + v * dt  # Euler step
    return x

torch.manual_seed(0)
model = ToyFlowNet()
for nfe in [5, 10, 50]:
    samples = euler_sample(model, n_steps=nfe)
    print(f'NFE={nfe:3d}: sample mean={samples.mean():.4f}, std={samples.std():.4f}')
```

## Comparing DDPM and Flow Matching

```python
import torch
import torch.nn as nn
import time

def benchmark_sampler(model, sampler_name, n_steps, n_samples=256, device='cpu'):
    x = torch.randn(n_samples, 2, device=device)
    dt = 1.0 / n_steps
    start = time.perf_counter()
    with torch.no_grad():
        for step in range(n_steps):
            t = torch.full((n_samples,), step * dt, device=device)
            v = model(x, t)
            if sampler_name == 'ddpm':
                # DDPM adds noise at each step (stochastic)
                noise_scale = (dt ** 0.5) * 0.1
                x = x - v * dt + noise_scale * torch.randn_like(x)
            else:
                # Flow matching: pure ODE, no noise
                x = x + v * dt
    elapsed = (time.perf_counter() - start) * 1000
    return elapsed, x

torch.manual_seed(0)
model = nn.Sequential(nn.Linear(3, 64), nn.SiLU(), nn.Linear(64, 2))
print(f'{"Method":<25} {"NFE":>5} {"Time (ms)":>12} {"Sample std":>12}')
for name, nfe in [('DDPM', 1000), ('Flow Matching', 50), ('Flow Matching', 10)]:
    ms, samples = benchmark_sampler(model, 'ddpm' if name == 'DDPM' else 'fm', nfe)
    print(f'{name:<25} {nfe:>5} {ms:>12.1f} {samples.std():>12.4f}')
```

## Why Straight Trajectories Help

DDPM paths are curved because each denoising step removes a small amount of noise while following the score field, which varies with x and t. The curvature means that a simple ODE integrator needs many steps to stay on the path. OT-CFM paths are nearly straight: a particle moves at constant velocity from noise to data. Straight paths have near-zero curvature, so a first-order Euler integrator makes minimal discretisation error even with very large step sizes. This is why flow matching models achieve competitive FID at 10 NFE while DDPM requires 1000.

## Production Applications

Flow matching has been adopted at scale in several production systems. Stable Diffusion 3 uses a multi-modal DiT backbone with flow matching instead of DDPM, reducing inference steps by 10× while improving prompt adherence. Meta Voicebox uses continuous-time flow matching for zero-shot text-to-speech synthesis across six languages. Meta Seamless uses flow matching for expressive speech-to-speech translation. The shared advantage is fewer NFE at inference, which reduces latency and cost in production serving.

> **NFE vs Quality Tradeoff**: Flow matching with 10 NFE often matches DDPM at 1000 NFE on FID, but individual samples may differ in detail quality. For highest-fidelity generation, 20-50 NFE with a higher-order solver (e.g. DPM-Solver++) closes most of the gap. OT-CFM consistently requires fewer steps than plain CFM due to straighter paths — if inference cost matters, always use OT pairing during training.

| Method | Trajectory Shape | NFE (typical) | Training Loss | Sample Quality | Simplicity |
| --- | --- | --- | --- | --- | --- |
| DDPM | Curved SDE path | 1000 | Noise prediction (L_simple) | High (baseline) | Simple loss, many steps |
| DDIM | Curved ODE path (same model) | 50–250 | Same as DDPM — no retraining | Matches DDPM | Free — no retraining needed |
| Flow Matching (CFM) | Near-straight ODE path | 20–100 | Velocity regression (MSE) | Competitive with DDPM | Simple — linear path |
| OT-CFM | Straight ODE path | 5–30 | Velocity regression (OT pairs) | High, fewer steps | Moderate — mini-batch OT |
| Consistency Models | One or few steps | 1–4 | Consistency function distillation | Good (slightly below FM) | Complex — requires teacher |

- CFM loss is a simple MSE on velocity — no variance weighting, no log-SNR reweighting required.
- Mini-batch OT pairing with linear_sum_assignment has O(B³) cost — use batch sizes of 256-512 for tractability.
- Flow matching is a special case of continuous normalising flows (CNFs) but trained with a simulation-free objective.
- The same architecture (U-Net or DiT) works for both DDPM and flow matching — only the training objective changes.
- SD3 adds classifier-free guidance to flow matching exactly as in DDPM: run conditional and unconditional paths and interpolate.

---

