---
title: "Glow — Generative Flow with Invertible 1×1 Convolutions"
slug: "glow-generative-flow"
description: "Glow (Kingma & Dhariwal 2018) improves RealNVP with learnable 1x1 convolutions (LU decomposition for O(c) log-det), Actnorm (data-dependent scale/bias), and affine coupling layers. Covers multi-scale architecture, latent space manipulation, and attribute arithmetic in z-space."
tags: ["deep-learning", "generative-models", "diffusion-models", "normalizing-flows"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Glow (Kingma \u0026 Dhariwal, 2018) is a generative flow that extends RealNVP with three improvements: Actnorm replaces batch normalization, learnable invertible 1×1 convolutions replace fixed channel permutations, and the affine coupling layer is retained. Together these allow exact likelihood computation, efficient sampling, and meaningful latent-space arithmetic such as smile → no-smile by vector subtraction in z-space."},{"type":"heading","level":2,"content":"Normalizing Flows Recap"},{"type":"text","content":"A normalizing flow defines a bijective mapping f: x → z between data space and a simple base distribution (typically N(0,I)). The change-of-variables formula gives log p(x) = log p_z(f(x)) + log|det J_f|. Training maximizes this log-likelihood. The key constraint is that f must be invertible and its Jacobian determinant must be tractable. Glow stacks K steps of flow at L levels in a multi-scale architecture, factoring out half the channels at each level to keep computation manageable."},{"type":"heading","level":2,"content":"Actnorm — Data-Dependent Initialization"},{"type":"text","content":"Actnorm is a per-channel affine transformation z = scale ∘ (x + bias) where scale and bias are learnable parameters initialized from the first batch so that the output has zero mean and unit variance. This is a valid alternative to batch normalization that does not depend on batch statistics at inference time. The log-determinant is H × W × Σ log|scale_c|, computed in O(c) time."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass Actnorm(nn.Module):\n    \"\"\"Data-dependent init: after first batch, output has mean=0, std=1.\"\"\"\n    def __init__(self, c):\n        super().__init__()\n        self.scale = nn.Parameter(torch.ones(1, c, 1, 1))\n        self.bias  = nn.Parameter(torch.zeros(1, c, 1, 1))\n        self.initialized = False\n\n    @torch.no_grad()\n    def initialize(self, x):\n        mean = x.mean([0, 2, 3], keepdim=True)\n        std  = x.std([0, 2, 3],  keepdim=True).clamp(min=1e-6)\n        self.bias.copy_(-mean)\n        self.scale.copy_(1.0 / std)\n        self.initialized = True\n\n    def forward(self, x):\n        if not self.initialized:\n            self.initialize(x)\n        _, _, H, W = x.shape\n        z = self.scale * (x + self.bias)\n        log_det = H * W * self.scale.abs().log().sum()\n        return z, log_det\n\n    def inverse(self, z):\n        return z / self.scale - self.bias\n\nlayer = Actnorm(3)\nx = torch.randn(16, 3, 8, 8) * 5 + 2\nz, ld = layer.forward(x)\nprint(f\"Before: mean={x.mean():.3f}  std={x.std():.3f}\")\nprint(f\"After:  mean={z.mean():.3f}  std={z.std():.3f}\")\nprint(f\"Reconstruction: {(x - layer.inverse(z)).abs().max():.2e}\")"},{"type":"heading","level":2,"content":"Invertible 1×1 Convolution"},{"type":"text","content":"RealNVP uses fixed channel permutations (reverse or shuffle) between coupling layers. Glow generalizes this to a learned square matrix W applied as a 1×1 convolution. The log-determinant is H × W × log|det W|, which naively costs O(c³). The LU decomposition W = P L U reduces this to O(c): log|det W| = Σ log|diag(U)_i|, computed from the diagonal of U alone. P is a fixed permutation matrix, L and U are triangular with learnable entries."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass Invertible1x1Conv(nn.Module):\n    \"\"\"LU-decomposed invertible 1x1 conv: log|det W| = sum(log|diag S|), O(c).\"\"\"\n    def __init__(self, c):\n        super().__init__()\n        W = torch.linalg.qr(torch.randn(c, c))[0]\n        self.register_buffer(\u0027P\u0027, torch.eye(c)[torch.randperm(c)])\n        self.L     = nn.Parameter(torch.tril(W, -1) + torch.eye(c))\n        self.U     = nn.Parameter(torch.triu(W,  1))\n        self.log_s = nn.Parameter(W.diag().abs().log())\n        self.s_sgn = nn.Parameter(W.diag().sign(), requires_grad=False)\n        self.c = c\n\n    def _W(self):\n        L = torch.tril(self.L, -1) + torch.eye(self.c, device=self.L.device)\n        U = torch.triu(self.U,  1) + torch.diag(self.s_sgn * self.log_s.exp())\n        return self.P @ L @ U\n\n    def forward(self, x):\n        B, C, H, W = x.shape\n        z = F.conv2d(x, self._W().view(C, C, 1, 1))\n        return z, H * W * self.log_s.sum()\n\n    def inverse(self, z):\n        W_inv = torch.linalg.inv(self._W()).view(self.c, self.c, 1, 1)\n        return F.conv2d(z, W_inv)\n\nc, B, H = 8, 2, 4\nlayer = Invertible1x1Conv(c)\nx = torch.randn(B, c, H, H)\nz, ld = layer.forward(x)\nprint(f\"Reconstruction error: {(x - layer.inverse(z)).abs().max():.2e}\")\nprint(f\"Log-det: {ld.item():.4f}\")\nprint(\"Cost: O(c^3) matrix multiply once, O(c) log-det from diagonal of S\")"},{"type":"heading","level":2,"content":"Affine Coupling Layer and Full Glow Step"},{"type":"text","content":"The affine coupling layer splits channels into two halves x_a, x_b. The first half passes through unchanged; a small convolutional network computes (log_s, t) = NN(x_a), and x_b is transformed as z_b = x_b ∘ exp(log_s) + t. The inverse is exact: x_b = (z_b - t) ∘ exp(-log_s). One Glow step stacks: Actnorm → Inv-1×1-Conv → Affine-Coupling, each contributing to the total log-det."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass AffineCoupling(nn.Module):\n    def __init__(self, c_half, hidden=128):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Conv2d(c_half, hidden, 3, padding=1), nn.ReLU(),\n            nn.Conv2d(hidden, hidden, 1), nn.ReLU(),\n            nn.Conv2d(hidden, c_half * 2, 3, padding=1))\n\n    def forward(self, x):\n        xa, xb = x.chunk(2, dim=1)\n        log_s, t = self.net(xa).chunk(2, dim=1)\n        log_s = log_s.tanh()\n        zb = xb * log_s.exp() + t\n        return torch.cat([xa, zb], dim=1), log_s.sum([1, 2, 3])\n\n    def inverse(self, z):\n        za, zb = z.chunk(2, dim=1)\n        log_s, t = self.net(za).chunk(2, dim=1)\n        xb = (zb - t) * (-log_s.tanh()).exp()\n        return torch.cat([za, xb], dim=1)\n\nclass GlowStep(nn.Module):\n    \"\"\"One Glow step: Actnorm -\u003e Inv-1x1-Conv -\u003e Affine Coupling.\"\"\"\n    def __init__(self, c):\n        super().__init__()\n        self.actnorm  = Actnorm(c)\n        self.inv1x1   = Invertible1x1Conv(c)\n        self.coupling = AffineCoupling(c // 2)\n\n    def forward(self, x):\n        x, ld1 = self.actnorm(x)\n        x, ld2 = self.inv1x1(x)\n        x, ld3 = self.coupling(x)\n        return x, ld1 + ld2 + ld3\n\nc, B, H = 8, 4, 8\nstep = GlowStep(c)\nx = torch.randn(B, c, H, H)\nz, log_det = step.forward(x)\nprint(f\"x: {x.shape} -\u003e z: {z.shape}  log_det.mean={log_det.mean():.3f}\")"},{"type":"heading","level":2,"content":"Multi-Scale Architecture"},{"type":"text","content":"Glow uses a multi-scale design where, after every L steps, half the channels are factored out: z_factored = x[:, :c//2], x = x[:, c//2:]. The factored-out channels are combined with the output at the end. This reduces spatial resolution and channel count as depth increases, keeping memory and computation tractable. The factored-out portions form independent Gaussian factors; the final log-likelihood sums over all levels."},{"type":"list","ordered":false,"items":["Level 0: K flow steps on full (C, H, W) feature map, factor out C//2 channels.","Level 1: K flow steps on (C//2, H//2, W//2) after squeeze, factor out half again.","Level L-1: final level processes smallest spatial resolution, all channels retained.","Squeeze operation: reshape (C, H, W) -\u003e (4C, H/2, W/2) before each new level.","At generation: sample each factored tensor from N(0, σ²), run all inverse flows."]},{"type":"heading","level":2,"content":"Latent Space Manipulation"},{"type":"text","content":"Because Glow learns an exact invertible mapping, attribute manipulation is precise: encode a dataset of images, separate by attribute label, compute the mean z-vector for each class, and the difference δ = z_pos_mean - z_neg_mean is an attribute direction. Adding αδ to any latent code moves the image along that attribute while preserving other features. This works for smile, age, gender, and other CelebA attributes."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef compute_attribute_direction(z_pos_list, z_neg_list):\n    \"\"\"Mean difference in z-space between positive and negative attribute examples.\"\"\"\n    z_pos = torch.cat(z_pos_list).mean(0)\n    z_neg = torch.cat(z_neg_list).mean(0)\n    delta = z_pos - z_neg\n    return delta / delta.norm()   # unit direction vector\n\ndef apply_attribute(model_inv, z, attr_vec, strengths=(-2, -1, 0, 1, 2)):\n    \"\"\"Traverse latent space along attribute direction at multiple strengths.\"\"\"\n    results = {}\n    with torch.no_grad():\n        for alpha in strengths:\n            z_edit = z + alpha * attr_vec.to(z.device)\n            results[alpha] = model_inv(z_edit)\n    return results\n\ntorch.manual_seed(42)\nd_z = 512\nz_pos = [torch.randn(32, d_z) + 0.5 for _ in range(3)]\nz_neg = [torch.randn(32, d_z) - 0.5 for _ in range(3)]\nattr_smile = compute_attribute_direction(z_pos, z_neg)\n\nz_test = torch.randn(1, d_z)\nfor alpha in [-2.0, 0.0, 2.0]:\n    z_edit = z_test + alpha * attr_smile\n    dist = (z_edit - z_test).norm().item()\n    print(f\"alpha={alpha:+.1f}  ||z_edit - z||={dist:.3f}  mean={z_edit.mean():.3f}\")\nprint(\"Linear interpolation in z-space corresponds to smooth attribute morphing\")"},{"type":"callout","variant":"info","title":"Temperature Scaling at Synthesis","content":"Sampling z ~ N(0, σ²) with σ \u003c 1 (e.g. σ=0.7) produces sharper, more realistic images at the cost of diversity. The model was trained with σ=1 but inference benefits from lower temperature. This is because the model learns to assign low-likelihood regions to unlikely but still plausible data; sampling from a tighter distribution avoids these artifacts."},{"type":"heading","level":2,"content":"RealNVP vs Glow Comparison"},{"type":"table","headers":["Property","RealNVP","Glow"],"rows":[["Channel permutation","Fixed reverse or shuffle","Learnable 1×1 conv (W = PLU)"],["Normalization","Batch Norm (batch-dependent)","Actnorm (data-init, no batch dep.)"],["Log-det cost","O(1) — coupling only","O(c) — diagonal of U in LU decomp"],["Bits/dim on CelebA 256","~3.49","~3.35 (improved by learnable perm)"],["Latent manipulation","Approximate (fixed permutation)","Precise arithmetic in z-space"],["Multi-scale","Yes (factor out half per level)","Yes (same pattern, more levels)"]]},{"type":"heading","level":2,"content":"Synthesis and Interpolation"},{"type":"text","content":"To generate an image: sample z ~ N(0, σ²I) and pass through the inverse flow f⁻¹(z). For interpolation between two images x₁, x₂: encode both to z₁ = f(x₁), z₂ = f(x₂), then decode z(λ) = (1-λ)z₁ + λz₂ for λ ∈ [0,1]. Interpolation in z-space is linear; the resulting images smoothly transition. This works better than pixel-space interpolation because z-space has a structured Gaussian geometry."}]"
---
# Glow — Generative Flow with Invertible 1×1 Convolutions

Glow (Kingma & Dhariwal, 2018) is a generative flow that extends RealNVP with three improvements: Actnorm replaces batch normalization, learnable invertible 1×1 convolutions replace fixed channel permutations, and the affine coupling layer is retained. Together these allow exact likelihood computation, efficient sampling, and meaningful latent-space arithmetic such as smile → no-smile by vector subtraction in z-space.

## Normalizing Flows Recap

A normalizing flow defines a bijective mapping f: x → z between data space and a simple base distribution (typically N(0,I)). The change-of-variables formula gives log p(x) = log p_z(f(x)) + log|det J_f|. Training maximizes this log-likelihood. The key constraint is that f must be invertible and its Jacobian determinant must be tractable. Glow stacks K steps of flow at L levels in a multi-scale architecture, factoring out half the channels at each level to keep computation manageable.

## Actnorm — Data-Dependent Initialization

Actnorm is a per-channel affine transformation z = scale ∘ (x + bias) where scale and bias are learnable parameters initialized from the first batch so that the output has zero mean and unit variance. This is a valid alternative to batch normalization that does not depend on batch statistics at inference time. The log-determinant is H × W × Σ log|scale_c|, computed in O(c) time.

```python
import torch
import torch.nn as nn

class Actnorm(nn.Module):
    """Data-dependent init: after first batch, output has mean=0, std=1."""
    def __init__(self, c):
        super().__init__()
        self.scale = nn.Parameter(torch.ones(1, c, 1, 1))
        self.bias  = nn.Parameter(torch.zeros(1, c, 1, 1))
        self.initialized = False

    @torch.no_grad()
    def initialize(self, x):
        mean = x.mean([0, 2, 3], keepdim=True)
        std  = x.std([0, 2, 3],  keepdim=True).clamp(min=1e-6)
        self.bias.copy_(-mean)
        self.scale.copy_(1.0 / std)
        self.initialized = True

    def forward(self, x):
        if not self.initialized:
            self.initialize(x)
        _, _, H, W = x.shape
        z = self.scale * (x + self.bias)
        log_det = H * W * self.scale.abs().log().sum()
        return z, log_det

    def inverse(self, z):
        return z / self.scale - self.bias

layer = Actnorm(3)
x = torch.randn(16, 3, 8, 8) * 5 + 2
z, ld = layer.forward(x)
print(f"Before: mean={x.mean():.3f}  std={x.std():.3f}")
print(f"After:  mean={z.mean():.3f}  std={z.std():.3f}")
print(f"Reconstruction: {(x - layer.inverse(z)).abs().max():.2e}")
```

## Invertible 1×1 Convolution

RealNVP uses fixed channel permutations (reverse or shuffle) between coupling layers. Glow generalizes this to a learned square matrix W applied as a 1×1 convolution. The log-determinant is H × W × log|det W|, which naively costs O(c³). The LU decomposition W = P L U reduces this to O(c): log|det W| = Σ log|diag(U)_i|, computed from the diagonal of U alone. P is a fixed permutation matrix, L and U are triangular with learnable entries.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class Invertible1x1Conv(nn.Module):
    """LU-decomposed invertible 1x1 conv: log|det W| = sum(log|diag S|), O(c)."""
    def __init__(self, c):
        super().__init__()
        W = torch.linalg.qr(torch.randn(c, c))[0]
        self.register_buffer('P', torch.eye(c)[torch.randperm(c)])
        self.L     = nn.Parameter(torch.tril(W, -1) + torch.eye(c))
        self.U     = nn.Parameter(torch.triu(W,  1))
        self.log_s = nn.Parameter(W.diag().abs().log())
        self.s_sgn = nn.Parameter(W.diag().sign(), requires_grad=False)
        self.c = c

    def _W(self):
        L = torch.tril(self.L, -1) + torch.eye(self.c, device=self.L.device)
        U = torch.triu(self.U,  1) + torch.diag(self.s_sgn * self.log_s.exp())
        return self.P @ L @ U

    def forward(self, x):
        B, C, H, W = x.shape
        z = F.conv2d(x, self._W().view(C, C, 1, 1))
        return z, H * W * self.log_s.sum()

    def inverse(self, z):
        W_inv = torch.linalg.inv(self._W()).view(self.c, self.c, 1, 1)
        return F.conv2d(z, W_inv)

c, B, H = 8, 2, 4
layer = Invertible1x1Conv(c)
x = torch.randn(B, c, H, H)
z, ld = layer.forward(x)
print(f"Reconstruction error: {(x - layer.inverse(z)).abs().max():.2e}")
print(f"Log-det: {ld.item():.4f}")
print("Cost: O(c^3) matrix multiply once, O(c) log-det from diagonal of S")
```

## Affine Coupling Layer and Full Glow Step

The affine coupling layer splits channels into two halves x_a, x_b. The first half passes through unchanged; a small convolutional network computes (log_s, t) = NN(x_a), and x_b is transformed as z_b = x_b ∘ exp(log_s) + t. The inverse is exact: x_b = (z_b - t) ∘ exp(-log_s). One Glow step stacks: Actnorm → Inv-1×1-Conv → Affine-Coupling, each contributing to the total log-det.

```python
import torch
import torch.nn as nn

class AffineCoupling(nn.Module):
    def __init__(self, c_half, hidden=128):
        super().__init__()
        self.net = nn.Sequential(
            nn.Conv2d(c_half, hidden, 3, padding=1), nn.ReLU(),
            nn.Conv2d(hidden, hidden, 1), nn.ReLU(),
            nn.Conv2d(hidden, c_half * 2, 3, padding=1))

    def forward(self, x):
        xa, xb = x.chunk(2, dim=1)
        log_s, t = self.net(xa).chunk(2, dim=1)
        log_s = log_s.tanh()
        zb = xb * log_s.exp() + t
        return torch.cat([xa, zb], dim=1), log_s.sum([1, 2, 3])

    def inverse(self, z):
        za, zb = z.chunk(2, dim=1)
        log_s, t = self.net(za).chunk(2, dim=1)
        xb = (zb - t) * (-log_s.tanh()).exp()
        return torch.cat([za, xb], dim=1)

class GlowStep(nn.Module):
    """One Glow step: Actnorm -> Inv-1x1-Conv -> Affine Coupling."""
    def __init__(self, c):
        super().__init__()
        self.actnorm  = Actnorm(c)
        self.inv1x1   = Invertible1x1Conv(c)
        self.coupling = AffineCoupling(c // 2)

    def forward(self, x):
        x, ld1 = self.actnorm(x)
        x, ld2 = self.inv1x1(x)
        x, ld3 = self.coupling(x)
        return x, ld1 + ld2 + ld3

c, B, H = 8, 4, 8
step = GlowStep(c)
x = torch.randn(B, c, H, H)
z, log_det = step.forward(x)
print(f"x: {x.shape} -> z: {z.shape}  log_det.mean={log_det.mean():.3f}")
```

## Multi-Scale Architecture

Glow uses a multi-scale design where, after every L steps, half the channels are factored out: z_factored = x[:, :c//2], x = x[:, c//2:]. The factored-out channels are combined with the output at the end. This reduces spatial resolution and channel count as depth increases, keeping memory and computation tractable. The factored-out portions form independent Gaussian factors; the final log-likelihood sums over all levels.

- Level 0: K flow steps on full (C, H, W) feature map, factor out C//2 channels.
- Level 1: K flow steps on (C//2, H//2, W//2) after squeeze, factor out half again.
- Level L-1: final level processes smallest spatial resolution, all channels retained.
- Squeeze operation: reshape (C, H, W) -> (4C, H/2, W/2) before each new level.
- At generation: sample each factored tensor from N(0, σ²), run all inverse flows.

## Latent Space Manipulation

Because Glow learns an exact invertible mapping, attribute manipulation is precise: encode a dataset of images, separate by attribute label, compute the mean z-vector for each class, and the difference δ = z_pos_mean - z_neg_mean is an attribute direction. Adding αδ to any latent code moves the image along that attribute while preserving other features. This works for smile, age, gender, and other CelebA attributes.

```python
import torch
import numpy as np

def compute_attribute_direction(z_pos_list, z_neg_list):
    """Mean difference in z-space between positive and negative attribute examples."""
    z_pos = torch.cat(z_pos_list).mean(0)
    z_neg = torch.cat(z_neg_list).mean(0)
    delta = z_pos - z_neg
    return delta / delta.norm()   # unit direction vector

def apply_attribute(model_inv, z, attr_vec, strengths=(-2, -1, 0, 1, 2)):
    """Traverse latent space along attribute direction at multiple strengths."""
    results = {}
    with torch.no_grad():
        for alpha in strengths:
            z_edit = z + alpha * attr_vec.to(z.device)
            results[alpha] = model_inv(z_edit)
    return results

torch.manual_seed(42)
d_z = 512
z_pos = [torch.randn(32, d_z) + 0.5 for _ in range(3)]
z_neg = [torch.randn(32, d_z) - 0.5 for _ in range(3)]
attr_smile = compute_attribute_direction(z_pos, z_neg)

z_test = torch.randn(1, d_z)
for alpha in [-2.0, 0.0, 2.0]:
    z_edit = z_test + alpha * attr_smile
    dist = (z_edit - z_test).norm().item()
    print(f"alpha={alpha:+.1f}  ||z_edit - z||={dist:.3f}  mean={z_edit.mean():.3f}")
print("Linear interpolation in z-space corresponds to smooth attribute morphing")
```

> **Temperature Scaling at Synthesis**: Sampling z ~ N(0, σ²) with σ < 1 (e.g. σ=0.7) produces sharper, more realistic images at the cost of diversity. The model was trained with σ=1 but inference benefits from lower temperature. This is because the model learns to assign low-likelihood regions to unlikely but still plausible data; sampling from a tighter distribution avoids these artifacts.

## RealNVP vs Glow Comparison

| Property | RealNVP | Glow |
| --- | --- | --- |
| Channel permutation | Fixed reverse or shuffle | Learnable 1×1 conv (W = PLU) |
| Normalization | Batch Norm (batch-dependent) | Actnorm (data-init, no batch dep.) |
| Log-det cost | O(1) — coupling only | O(c) — diagonal of U in LU decomp |
| Bits/dim on CelebA 256 | ~3.49 | ~3.35 (improved by learnable perm) |
| Latent manipulation | Approximate (fixed permutation) | Precise arithmetic in z-space |
| Multi-scale | Yes (factor out half per level) | Yes (same pattern, more levels) |

## Synthesis and Interpolation

To generate an image: sample z ~ N(0, σ²I) and pass through the inverse flow f⁻¹(z). For interpolation between two images x₁, x₂: encode both to z₁ = f(x₁), z₂ = f(x₂), then decode z(λ) = (1-λ)z₁ + λz₂ for λ ∈ [0,1]. Interpolation in z-space is linear; the resulting images smoothly transition. This works better than pixel-space interpolation because z-space has a structured Gaussian geometry.

