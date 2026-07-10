---
title: "MAF and IAF — Autoregressive Normalizing Flows"
slug: "maf-iaf-flows"
description: "MAF (Masked Autoregressive Flow) evaluates density in O(1) using MADE but samples in O(d). IAF reverses the trade-off: O(1) sampling, O(d) density. Covers MADE masking, forward/inverse passes, and when to use each (density estimation vs VAE posteriors)."
tags: ["deep-learning", "generative-models", "diffusion-models", "normalizing-flows"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Autoregressive models factorize p(x) = Π p(x_i | x_{\u003ci}). MAF (Papamakarios et al., 2017) reframes this as a normalizing flow where each conditional is a Gaussian: p(x_i | x_{\u003ci}) = N(μ_i(x_{\u003ci}), σ_i(x_{\u003ci})). The resulting transformation y_i = (x_i - μ_i) / σ_i is an invertible affine map. Because MADE computes all μ_i, σ_i in a single forward pass, density evaluation is O(1). Sampling requires inverting the autoregressive structure sequentially, making it O(d). IAF (Kingma et al., 2016) reverses the parameterization to get fast sampling at the cost of slow density."},{"type":"heading","level":2,"content":"Autoregressive Models as Normalizing Flows"},{"type":"text","content":"A normalizing flow requires a bijective mapping f: x → z with tractable Jacobian determinant. An autoregressive model where y_i = (x_i - μ_i(x_{\u003ci})) / σ_i(x_{\u003ci}) is exactly this: the Jacobian is lower-triangular (output y_i depends on x_{≤i} but the transformation of x_i depends only on x_{\u003ci}), so its determinant is the product of diagonal elements: det J = Π_i (1/σ_i). The log-determinant is -Σ_i log σ_i. This structure — lower-triangular Jacobian, unit-diagonal or diagonal — is the key that links autoregressive models to normalizing flows and justifies using MADE as the backbone."},{"type":"heading","level":2,"content":"MADE — Masked Autoencoder for Distribution Estimation"},{"type":"text","content":"MADE (Germain et al., 2015) implements a masked MLP that computes all conditionals p(x_i | x_{\u003ci}) in a single forward pass. Each hidden unit is assigned a degree m ∈ {0, ..., d-1}; connections are masked so that unit j in layer l can only receive input from units in layer l-1 with degree ≤ m_j. The output for x_i uses only hidden units with degree \u003c i, enforcing the autoregressive property. The mask matrices are fixed at initialization; the weights are learned normally."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass MADE(nn.Module):\n    \"\"\"Masked Autoencoder for Distribution Estimation (Germain et al. 2015).\n    Enforces output_i depends only on inputs 0..i-1 via static masks.\"\"\"\n    def __init__(self, d, hidden=128, n_out=2):\n        super().__init__()\n        self.d, self.n_out = d, n_out\n        m_in  = torch.arange(d)\n        m_h   = torch.randint(0, d - 1, (hidden,))\n        m_out = torch.arange(d).repeat(n_out)\n        # mask[i,j]=1 iff hidden unit i can see input j\n        self.mask1 = (m_h.unsqueeze(1) \u003e= m_in.unsqueeze(0)).float()   # (h, d)\n        # mask[i,j]=1 iff output i can see hidden unit j (strict inequality)\n        self.mask2 = (m_out.unsqueeze(1) \u003e m_h.unsqueeze(0)).float()   # (d*n, h)\n        self.fc1 = nn.Linear(d, hidden)\n        self.fc2 = nn.Linear(hidden, d * n_out)\n        self.register_buffer(\u0027_m1\u0027, self.mask1)\n        self.register_buffer(\u0027_m2\u0027, self.mask2)\n\n    def forward(self, x):\n        h = F.relu(F.linear(x, self.fc1.weight * self._m1, self.fc1.bias))\n        o = F.linear(h, self.fc2.weight * self._m2, self.fc2.bias)\n        return o.view(x.shape[0], self.d, self.n_out)\n\nd, B = 8, 16\nmade = MADE(d, hidden=64)\nx = torch.randn(B, d)\nout = made(x)\nprint(f\"Output shape: {out.shape}  (batch={B}, d={d}, 2 params per dim)\")\nprint(\"MADE: all conditionals computed in ONE forward pass -\u003e O(1) density eval\")"},{"type":"heading","level":2,"content":"MAF — Forward Pass (Density Evaluation)"},{"type":"text","content":"In MAF the transformation is y_i = (x_i - μ_i(x_{\u003ci})) × exp(-α_i(x_{\u003ci})). MADE computes all (μ_i, α_i) in one pass from x, so the forward transformation (x → y, used for density evaluation) is O(1). The log-determinant is diagonal: log|det J| = -Σ_i α_i(x_{\u003ci}), which comes out of the same MADE pass. Training a stack of MAF layers by maximum likelihood is therefore efficient."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass MAFLayer(nn.Module):\n    \"\"\"Single MAF layer. Forward (density) is O(1); inverse (sample) is O(d).\"\"\"\n    def __init__(self, d, hidden=128):\n        super().__init__()\n        self.made = MADE(d, hidden=hidden, n_out=2)\n\n    def forward(self, x):\n        \"\"\"Density eval: one MADE pass computes all (mu_i, log_sigma_i).\"\"\"\n        params  = self.made(x)              # (B, d, 2)\n        mu      = params[..., 0]\n        log_sig = params[..., 1]\n        y       = (x - mu) * (-log_sig).exp()\n        log_det = -log_sig.sum(dim=-1)     # (B,)\n        return y, log_det\n\n    def log_prob(self, x):\n        y, log_det = self.forward(x)\n        log_pz = -0.5 * (y ** 2 + torch.log(torch.tensor(2 * torch.pi))).sum(-1)\n        return log_pz + log_det\n\nd, B = 8, 32\nlayer = MAFLayer(d)\nx = torch.randn(B, d)\ny, ld = layer.forward(x)\nlp   = layer.log_prob(x)\nprint(f\"x: {x.shape} -\u003e y: {y.shape}\")\nprint(f\"log_det range: [{ld.min():.2f}, {ld.max():.2f}]\")\nprint(f\"log_prob range: [{lp.min():.2f}, {lp.max():.2f}]\")\nprint(\"Forward (density): 1 MADE pass for entire batch -\u003e O(1)\")"},{"type":"heading","level":2,"content":"MAF — Inverse Pass (Sampling)"},{"type":"text","content":"To sample from MAF: draw y ~ N(0,I), then invert y_i = (x_i - μ_i) / σ_i to get x_i = y_i × σ_i(x_{\u003ci}) + μ_i(x_{\u003ci}). Computing x_i requires x_{\u003ci}, so the inversion is inherently sequential: compute x_1, then x_2 (using x_1), …, x_d (using x_{1:d-1}). Each step calls MADE once, yielding O(d) evaluations total. This makes MAF impractical as a decoder or posterior in a VAE where sampling speed matters."},{"type":"code","language":"python","content":"import torch\nimport time\n\ndef maf_inverse(layer, y, d):\n    \"\"\"Invert MAF: x_i = y_i * exp(log_s_i(x_{\u003ci})) + mu_i(x_{\u003ci}).\n    Requires d sequential MADE evaluations.\"\"\"\n    x = torch.zeros_like(y)\n    for i in range(d):\n        params  = layer.made(x)       # full MADE pass, but only output i used\n        mu_i    = params[:, i, 0]\n        log_si  = params[:, i, 1]\n        x[:, i] = y[:, i] * log_si.exp() + mu_i\n    return x\n\nd, B = 8, 16\nlayer  = MAFLayer(d)\nx_orig = torch.randn(B, d)\ny, _   = layer.forward(x_orig)\n\nt0 = time.perf_counter()\nx_rec = maf_inverse(layer, y, d)\nms_sample = (time.perf_counter() - t0) * 1000\n\nt0 = time.perf_counter()\n_, _ = layer.forward(x_orig)\nms_density = (time.perf_counter() - t0) * 1000\n\nprint(f\"Reconstruction error: {(x_orig - x_rec).abs().max():.2e}\")\nprint(f\"Density eval:  {ms_density:.3f} ms  [1 MADE pass]\")\nprint(f\"Sampling:      {ms_sample:.3f} ms  [{d} MADE passes]\")\nprint(f\"Slowdown: ~{ms_sample/max(ms_density,0.001):.1f}x  (scales as O(d))\")"},{"type":"heading","level":2,"content":"IAF — Inverse Autoregressive Flow"},{"type":"text","content":"IAF (Kingma et al., 2016) reverses the MAF parameterization: the transformation is z_i = μ_i(z_{\u003ci}) + σ_i(z_{\u003ci}) × ε_i where ε ~ N(0,I). Now the forward pass (sampling) is x → z, which is O(1) since all (μ_i, σ_i) are functions of z_{\u003ci} that can be computed via MADE in one pass from z. But density evaluation requires inverting: z_i = (x_i - μ_i(z_{\u003ci})) / σ_i(z_{\u003ci}), which is sequential in z_{\u003ci} — O(d) passes. IAF is therefore ideal as a flexible posterior approximation in VAEs (fast sampling during training), but not for standalone density estimation."},{"type":"callout","variant":"tip","title":"MAF vs IAF Use Cases","content":"Use MAF when you need fast density evaluation and can tolerate slow sampling: training a generative flow on log-likelihood, or as a prior. Use IAF when you need fast sampling and can tolerate slow density: as a flexible variational posterior q(z|x) in a VAE, where you sample z at every training step but rarely evaluate its exact density. Parallel WaveNet uses IAF as a fast student distilled from an autoregressive WaveNet teacher."},{"type":"heading","level":2,"content":"Density vs Sampling Speed Benchmark"},{"type":"code","language":"python","content":"import torch\nimport time\nimport numpy as np\n\ndef flow_benchmark(d=16, B=256, n_layers=4, n_trials=30):\n    \"\"\"Wall-clock comparison: density eval vs sampling in MAF.\"\"\"\n    dummy = torch.zeros(B, d, 2)\n    timings = {}\n\n    t0 = time.perf_counter()\n    for _ in range(n_trials):\n        x = torch.randn(B, d)\n        for _ in range(n_layers):\n            mu, log_s = dummy[..., 0], dummy[..., 1]\n            x = (x - mu) * (-log_s).exp()\n    timings[\u0027density\u0027] = (time.perf_counter() - t0) / n_trials * 1000\n\n    t0 = time.perf_counter()\n    for _ in range(n_trials):\n        z = torch.randn(B, d)\n        for _ in range(n_layers):\n            x_out = torch.zeros_like(z)\n            for i in range(d):\n                x_out[:, i] = z[:, i]   # placeholder sequential step\n            z = x_out\n    timings[\u0027sample\u0027] = (time.perf_counter() - t0) / n_trials * 1000\n\n    print(f\"Benchmark: d={d}, B={B}, layers={n_layers}\")\n    print(f\"  Density eval: {timings[\u0027density\u0027]:6.2f} ms  (O(1)/layer, parallel over d)\")\n    print(f\"  Sampling:     {timings[\u0027sample\u0027]:6.2f} ms  (O(d)/layer, serial)\")\n    print(f\"  Ratio:        {timings[\u0027sample\u0027]/max(timings[\u0027density\u0027],0.001):.1f}x\")\n    print(\"  IAF reverses: sampling O(1), density O(d)\")\n    print(\"  Use MAF for NF training; IAF for VAE posterior\")\n\nflow_benchmark(d=16)"},{"type":"heading","level":2,"content":"Flow Model Comparison"},{"type":"table","headers":["Model","Forward (density)","Inverse (sample)","Expressivity","Parallel train","Parallel sample"],"rows":[["NICE","O(1)","O(1)","Low (additive only)","Yes","Yes"],["RealNVP","O(1)","O(1)","Medium (affine coupling)","Yes","Yes"],["MAF","O(1) via MADE","O(d) sequential","High (autoregressive)","Yes","No"],["IAF","O(d) sequential","O(1) via MADE","High (autoregressive)","No (density needed)","Yes"],["Glow","O(1)","O(1)","High (learnable perm)","Yes","Yes"]]},{"type":"heading","level":2,"content":"Neural Spline Flows"},{"type":"text","content":"Neural Spline Flows (Durkan et al., 2019) replace the affine coupling (scale + shift) with a monotone rational-quadratic spline, greatly increasing expressivity without sacrificing invertibility or O(1) log-det. The spline is parameterized by K knot positions and derivatives; the inverse is computed analytically. NSF achieves significantly better bits/dim than affine-based flows on image benchmarks and is now widely used in physics-inspired generative models."},{"type":"list","ordered":false,"items":["Affine coupling: y = x * exp(s) + t — linear, limited expressivity in each layer.","Spline coupling: y = spline(x; W, H, D) — nonlinear monotone, much more expressive.","Inverse: analytic (solve quadratic for rational-quadratic spline) — no sequential steps.","Log-det: derivative of spline — still O(1) and numerically stable.","Trade-off: more compute per layer but fewer layers needed for equivalent quality."]}]"
---
# MAF and IAF — Autoregressive Normalizing Flows

Autoregressive models factorize p(x) = Π p(x_i | x_{<i}). MAF (Papamakarios et al., 2017) reframes this as a normalizing flow where each conditional is a Gaussian: p(x_i | x_{<i}) = N(μ_i(x_{<i}), σ_i(x_{<i})). The resulting transformation y_i = (x_i - μ_i) / σ_i is an invertible affine map. Because MADE computes all μ_i, σ_i in a single forward pass, density evaluation is O(1). Sampling requires inverting the autoregressive structure sequentially, making it O(d). IAF (Kingma et al., 2016) reverses the parameterization to get fast sampling at the cost of slow density.

## Autoregressive Models as Normalizing Flows

A normalizing flow requires a bijective mapping f: x → z with tractable Jacobian determinant. An autoregressive model where y_i = (x_i - μ_i(x_{<i})) / σ_i(x_{<i}) is exactly this: the Jacobian is lower-triangular (output y_i depends on x_{≤i} but the transformation of x_i depends only on x_{<i}), so its determinant is the product of diagonal elements: det J = Π_i (1/σ_i). The log-determinant is -Σ_i log σ_i. This structure — lower-triangular Jacobian, unit-diagonal or diagonal — is the key that links autoregressive models to normalizing flows and justifies using MADE as the backbone.

## MADE — Masked Autoencoder for Distribution Estimation

MADE (Germain et al., 2015) implements a masked MLP that computes all conditionals p(x_i | x_{<i}) in a single forward pass. Each hidden unit is assigned a degree m ∈ {0, ..., d-1}; connections are masked so that unit j in layer l can only receive input from units in layer l-1 with degree ≤ m_j. The output for x_i uses only hidden units with degree < i, enforcing the autoregressive property. The mask matrices are fixed at initialization; the weights are learned normally.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class MADE(nn.Module):
    """Masked Autoencoder for Distribution Estimation (Germain et al. 2015).
    Enforces output_i depends only on inputs 0..i-1 via static masks."""
    def __init__(self, d, hidden=128, n_out=2):
        super().__init__()
        self.d, self.n_out = d, n_out
        m_in  = torch.arange(d)
        m_h   = torch.randint(0, d - 1, (hidden,))
        m_out = torch.arange(d).repeat(n_out)
        # mask[i,j]=1 iff hidden unit i can see input j
        self.mask1 = (m_h.unsqueeze(1) >= m_in.unsqueeze(0)).float()   # (h, d)
        # mask[i,j]=1 iff output i can see hidden unit j (strict inequality)
        self.mask2 = (m_out.unsqueeze(1) > m_h.unsqueeze(0)).float()   # (d*n, h)
        self.fc1 = nn.Linear(d, hidden)
        self.fc2 = nn.Linear(hidden, d * n_out)
        self.register_buffer('_m1', self.mask1)
        self.register_buffer('_m2', self.mask2)

    def forward(self, x):
        h = F.relu(F.linear(x, self.fc1.weight * self._m1, self.fc1.bias))
        o = F.linear(h, self.fc2.weight * self._m2, self.fc2.bias)
        return o.view(x.shape[0], self.d, self.n_out)

d, B = 8, 16
made = MADE(d, hidden=64)
x = torch.randn(B, d)
out = made(x)
print(f"Output shape: {out.shape}  (batch={B}, d={d}, 2 params per dim)")
print("MADE: all conditionals computed in ONE forward pass -> O(1) density eval")
```

## MAF — Forward Pass (Density Evaluation)

In MAF the transformation is y_i = (x_i - μ_i(x_{<i})) × exp(-α_i(x_{<i})). MADE computes all (μ_i, α_i) in one pass from x, so the forward transformation (x → y, used for density evaluation) is O(1). The log-determinant is diagonal: log|det J| = -Σ_i α_i(x_{<i}), which comes out of the same MADE pass. Training a stack of MAF layers by maximum likelihood is therefore efficient.

```python
import torch
import torch.nn as nn

class MAFLayer(nn.Module):
    """Single MAF layer. Forward (density) is O(1); inverse (sample) is O(d)."""
    def __init__(self, d, hidden=128):
        super().__init__()
        self.made = MADE(d, hidden=hidden, n_out=2)

    def forward(self, x):
        """Density eval: one MADE pass computes all (mu_i, log_sigma_i)."""
        params  = self.made(x)              # (B, d, 2)
        mu      = params[..., 0]
        log_sig = params[..., 1]
        y       = (x - mu) * (-log_sig).exp()
        log_det = -log_sig.sum(dim=-1)     # (B,)
        return y, log_det

    def log_prob(self, x):
        y, log_det = self.forward(x)
        log_pz = -0.5 * (y ** 2 + torch.log(torch.tensor(2 * torch.pi))).sum(-1)
        return log_pz + log_det

d, B = 8, 32
layer = MAFLayer(d)
x = torch.randn(B, d)
y, ld = layer.forward(x)
lp   = layer.log_prob(x)
print(f"x: {x.shape} -> y: {y.shape}")
print(f"log_det range: [{ld.min():.2f}, {ld.max():.2f}]")
print(f"log_prob range: [{lp.min():.2f}, {lp.max():.2f}]")
print("Forward (density): 1 MADE pass for entire batch -> O(1)")
```

## MAF — Inverse Pass (Sampling)

To sample from MAF: draw y ~ N(0,I), then invert y_i = (x_i - μ_i) / σ_i to get x_i = y_i × σ_i(x_{<i}) + μ_i(x_{<i}). Computing x_i requires x_{<i}, so the inversion is inherently sequential: compute x_1, then x_2 (using x_1), …, x_d (using x_{1:d-1}). Each step calls MADE once, yielding O(d) evaluations total. This makes MAF impractical as a decoder or posterior in a VAE where sampling speed matters.

```python
import torch
import time

def maf_inverse(layer, y, d):
    """Invert MAF: x_i = y_i * exp(log_s_i(x_{<i})) + mu_i(x_{<i}).
    Requires d sequential MADE evaluations."""
    x = torch.zeros_like(y)
    for i in range(d):
        params  = layer.made(x)       # full MADE pass, but only output i used
        mu_i    = params[:, i, 0]
        log_si  = params[:, i, 1]
        x[:, i] = y[:, i] * log_si.exp() + mu_i
    return x

d, B = 8, 16
layer  = MAFLayer(d)
x_orig = torch.randn(B, d)
y, _   = layer.forward(x_orig)

t0 = time.perf_counter()
x_rec = maf_inverse(layer, y, d)
ms_sample = (time.perf_counter() - t0) * 1000

t0 = time.perf_counter()
_, _ = layer.forward(x_orig)
ms_density = (time.perf_counter() - t0) * 1000

print(f"Reconstruction error: {(x_orig - x_rec).abs().max():.2e}")
print(f"Density eval:  {ms_density:.3f} ms  [1 MADE pass]")
print(f"Sampling:      {ms_sample:.3f} ms  [{d} MADE passes]")
print(f"Slowdown: ~{ms_sample/max(ms_density,0.001):.1f}x  (scales as O(d))")
```

## IAF — Inverse Autoregressive Flow

IAF (Kingma et al., 2016) reverses the MAF parameterization: the transformation is z_i = μ_i(z_{<i}) + σ_i(z_{<i}) × ε_i where ε ~ N(0,I). Now the forward pass (sampling) is x → z, which is O(1) since all (μ_i, σ_i) are functions of z_{<i} that can be computed via MADE in one pass from z. But density evaluation requires inverting: z_i = (x_i - μ_i(z_{<i})) / σ_i(z_{<i}), which is sequential in z_{<i} — O(d) passes. IAF is therefore ideal as a flexible posterior approximation in VAEs (fast sampling during training), but not for standalone density estimation.

> **MAF vs IAF Use Cases**: Use MAF when you need fast density evaluation and can tolerate slow sampling: training a generative flow on log-likelihood, or as a prior. Use IAF when you need fast sampling and can tolerate slow density: as a flexible variational posterior q(z|x) in a VAE, where you sample z at every training step but rarely evaluate its exact density. Parallel WaveNet uses IAF as a fast student distilled from an autoregressive WaveNet teacher.

## Density vs Sampling Speed Benchmark

```python
import torch
import time
import numpy as np

def flow_benchmark(d=16, B=256, n_layers=4, n_trials=30):
    """Wall-clock comparison: density eval vs sampling in MAF."""
    dummy = torch.zeros(B, d, 2)
    timings = {}

    t0 = time.perf_counter()
    for _ in range(n_trials):
        x = torch.randn(B, d)
        for _ in range(n_layers):
            mu, log_s = dummy[..., 0], dummy[..., 1]
            x = (x - mu) * (-log_s).exp()
    timings['density'] = (time.perf_counter() - t0) / n_trials * 1000

    t0 = time.perf_counter()
    for _ in range(n_trials):
        z = torch.randn(B, d)
        for _ in range(n_layers):
            x_out = torch.zeros_like(z)
            for i in range(d):
                x_out[:, i] = z[:, i]   # placeholder sequential step
            z = x_out
    timings['sample'] = (time.perf_counter() - t0) / n_trials * 1000

    print(f"Benchmark: d={d}, B={B}, layers={n_layers}")
    print(f"  Density eval: {timings['density']:6.2f} ms  (O(1)/layer, parallel over d)")
    print(f"  Sampling:     {timings['sample']:6.2f} ms  (O(d)/layer, serial)")
    print(f"  Ratio:        {timings['sample']/max(timings['density'],0.001):.1f}x")
    print("  IAF reverses: sampling O(1), density O(d)")
    print("  Use MAF for NF training; IAF for VAE posterior")

flow_benchmark(d=16)
```

## Flow Model Comparison

| Model | Forward (density) | Inverse (sample) | Expressivity | Parallel train | Parallel sample |
| --- | --- | --- | --- | --- | --- |
| NICE | O(1) | O(1) | Low (additive only) | Yes | Yes |
| RealNVP | O(1) | O(1) | Medium (affine coupling) | Yes | Yes |
| MAF | O(1) via MADE | O(d) sequential | High (autoregressive) | Yes | No |
| IAF | O(d) sequential | O(1) via MADE | High (autoregressive) | No (density needed) | Yes |
| Glow | O(1) | O(1) | High (learnable perm) | Yes | Yes |

## Neural Spline Flows

Neural Spline Flows (Durkan et al., 2019) replace the affine coupling (scale + shift) with a monotone rational-quadratic spline, greatly increasing expressivity without sacrificing invertibility or O(1) log-det. The spline is parameterized by K knot positions and derivatives; the inverse is computed analytically. NSF achieves significantly better bits/dim than affine-based flows on image benchmarks and is now widely used in physics-inspired generative models.

- Affine coupling: y = x * exp(s) + t — linear, limited expressivity in each layer.
- Spline coupling: y = spline(x; W, H, D) — nonlinear monotone, much more expressive.
- Inverse: analytic (solve quadratic for rational-quadratic spline) — no sequential steps.
- Log-det: derivative of spline — still O(1) and numerically stable.
- Trade-off: more compute per layer but fewer layers needed for equivalent quality.

