---
title: "Uniformity and Alignment — Geometric Theory of Contrastive Learning"
slug: "uniformity-alignment-ssl"
description: "Wang and Isola (2020) decompose contrastive learning objectives into two geometric properties on the unit hypersphere: alignment (positive pairs attract) and uniformity (features spread evenly), providing a principled diagnostic framework for understanding and detecting representational collapse."
tags: ["deep-learning", "self-supervised-learning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Wang and Isola (2020) offered one of the clearest theoretical frameworks for understanding why contrastive learning works. They showed that contrastive loss on the unit hypersphere can be decomposed into two competing geometric properties: alignment (positive pairs should be close together) and uniformity (all features should be spread as uniformly as possible across the sphere). These two properties are not arbitrary — they correspond to an ideal representation that is maximally informative: positive pairs agree (alignment) and the entire feature space is used without collapse (uniformity)."},{"type":"heading","level":2,"content":"Alignment — Attracting Positive Pairs"},{"type":"text","content":"Alignment measures how well the encoder maps semantically similar inputs to nearby representations. For a distribution of positive pairs (x, x\u0027) drawn from the same image with different augmentations, the alignment loss is the expected squared Euclidean distance between their L2-normalised representations: L_align = E_{(x,x\u0027)~p_pos}[‖f(x) − f(x\u0027)‖²]. For unit-norm vectors, this equals 2(1 − cosine_similarity(f(x), f(x\u0027))). Perfect alignment (L_align = 0) means the encoder is invariant to augmentation — both views map to the exact same point. This is the simplest form of representation learning: invariance to nuisance variation."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\n\ndef alignment_loss(z1: torch.Tensor, z2: torch.Tensor, alpha: float = 2.0) -\u003e torch.Tensor:\n    \"\"\"Alignment loss: expected ||f(x) - f(x\u0027)||^alpha for positive pairs.\n    z1, z2: (N, D) L2-normalised embeddings of two augmented views.\n    alpha=2 gives squared Euclidean distance on unit sphere.\n    \"\"\"\n    z1 = F.normalize(z1, dim=1)  # ensure unit norm\n    z2 = F.normalize(z2, dim=1)\n    return (z1 - z2).norm(dim=1).pow(alpha).mean()\n\n\ndef alignment_via_cosine(z1: torch.Tensor, z2: torch.Tensor) -\u003e torch.Tensor:\n    \"\"\"Equivalent: L_align = 2 * (1 - mean cosine similarity).\"\"\"\n    z1 = F.normalize(z1, dim=1)\n    z2 = F.normalize(z2, dim=1)\n    cos_sim = (z1 * z2).sum(dim=1)   # (N,) cosine similarity per pair\n    return 2 * (1 - cos_sim.mean())\n\n\n# Demo: perfect alignment, random alignment, collapsed alignment\ntorch.manual_seed(42)\nz = F.normalize(torch.randn(64, 128), dim=1)\nprint(\u0027Perfect alignment (z1 == z2):  \u0027, alignment_loss(z, z).item())          # 0.0\n\nz2_rand = F.normalize(torch.randn(64, 128), dim=1)\nprint(\u0027Random alignment:               \u0027, alignment_loss(z, z2_rand).item())   # ~2.0\n\nz2_noise = F.normalize(z + 0.05 * torch.randn_like(z), dim=1)\nprint(\u0027Near-perfect alignment (noise):\u0027, alignment_loss(z, z2_noise).item())   # small"},{"type":"heading","level":2,"content":"Uniformity — Spreading Features on the Hypersphere"},{"type":"text","content":"Uniformity measures how evenly the encoder\u0027s output distribution covers the unit hypersphere. A completely uniform distribution maximises entropy — every dimension is used and no information is wasted. The uniformity loss uses a Gaussian kernel to measure the average pairwise similarity: L_uniform = log E_{x,y~p_data}[e^{-2‖f(x)−f(y)‖²}]. The Gaussian kernel e^{-2‖u−v‖²} decays from 1 (when u = v) to 0 (when u and v are orthogonal). The log ensures the scale is additive. Minimising L_uniform pushes features apart — the optimal solution is a uniform distribution on the sphere (a perfectly spread packing)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\n\ndef uniformity_loss(z: torch.Tensor, t: float = 2.0) -\u003e torch.Tensor:\n    \"\"\"Uniformity loss: log-average of Gaussian kernel over all pairs.\n    z: (N, D) L2-normalised embeddings.\n    t: Gaussian kernel bandwidth (default 2 gives e^{-2||u-v||^2}).\n    \"\"\"\n    z = F.normalize(z, dim=1)                        # (N, D)\n    # Pairwise squared distances: ||u-v||^2 = 2 - 2*u.v for unit vectors\n    sq_dists = 2 - 2 * (z @ z.T)                    # (N, N)\n    # Gaussian kernel; include all pairs (diagonal = self, contributes 1)\n    kernel   = torch.exp(-t * sq_dists)              # (N, N)\n    # Log average over all N^2 pairs\n    return kernel.mean().log()\n\n\n# Demo: collapsed (all same) vs uniform (random unit vectors)\ntorch.manual_seed(0)\nN, D = 256, 128\n\n# Collapsed: all embeddings identical\nz_collapsed = F.normalize(torch.ones(N, D), dim=1)\nprint(\u0027Uniformity (collapsed):\u0027, uniformity_loss(z_collapsed).item())   # near 0 (bad)\n\n# Random unit vectors approximate uniform distribution\nz_uniform = F.normalize(torch.randn(N, D), dim=1)\nprint(\u0027Uniformity (random):   \u0027, uniformity_loss(z_uniform).item())     # very negative (good)\n\n# Slight cluster structure\nz_mixed = F.normalize(torch.randn(N, D) * 0.5 + torch.randn(1, D), dim=1)\nprint(\u0027Uniformity (clustered):\u0027, uniformity_loss(z_mixed).item())       # between"},{"type":"heading","level":2,"content":"NT-Xent as Alignment Plus Uniformity"},{"type":"text","content":"Wang and Isola proved that the NT-Xent loss (used by SimCLR) asymptotically decomposes into the alignment and uniformity terms. The numerator of NT-Xent maximises the similarity of positive pairs — this is the alignment term. The denominator normalises against all pairs including negatives — this is the uniformity term (pushing features apart). As batch size → ∞, NT-Xent = −alignment_term + uniformity_constant. This decomposition shows that NT-Xent implicitly optimises both geometric properties simultaneously, explaining why it generalises beyond its original contrastive framing."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\n\ndef nt_xent_decomposed(z1: torch.Tensor, z2: torch.Tensor,\n                       temperature: float = 0.5) -\u003e dict:\n    \"\"\"Compute NT-Xent and its alignment + uniformity decomposition.\n    z1, z2: (N, D) L2-normalised embeddings.\n    Returns dict with total loss, alignment component, uniformity component.\n    \"\"\"\n    N = z1.size(0)\n    z1 = F.normalize(z1, dim=1)\n    z2 = F.normalize(z2, dim=1)\n    z  = torch.cat([z1, z2], dim=0)   # (2N, D)\n\n    # NT-Xent total loss\n    sim_mat = (z @ z.T) / temperature   # (2N, 2N)\n    mask    = torch.eye(2*N, dtype=torch.bool, device=z.device)\n    sim_mat.masked_fill_(mask, float(\u0027-inf\u0027))\n    labels  = torch.cat([torch.arange(N, 2*N), torch.arange(N)]).to(z.device)\n    nt_xent = F.cross_entropy(sim_mat, labels)\n\n    # Alignment component (log numerator, normalised)\n    pos_sim = (z1 * z2).sum(dim=1) / temperature   # (N,)\n    align   = -pos_sim.mean()\n\n    # Uniformity component (log denominator, approximation)\n    uniform = uniformity_loss(z, t=2.0)\n\n    return {\u0027nt_xent\u0027: nt_xent.item(), \u0027alignment\u0027: align.item(), \u0027uniformity\u0027: uniform.item()}\n\n\ntorch.manual_seed(7)\nz1 = F.normalize(torch.randn(128, 64), dim=1)\nz2 = F.normalize(torch.randn(128, 64), dim=1)\nresult = nt_xent_decomposed(z1, z2)\nfor k, v in result.items():\n    print(f\u0027{k:\u003e12}: {v:.4f}\u0027)"},{"type":"heading","level":2,"content":"Collapse Detection During Training"},{"type":"text","content":"One of the most practical applications of the alignment/uniformity decomposition is early collapse detection. Representational collapse — where the encoder maps all inputs to the same point — produces perfect alignment (L_align ≈ 0) but maximally bad uniformity (L_uniform ≈ 0, since the Gaussian kernel for identical vectors is 1, and log(1) = 0). By tracking both metrics independently during training, practitioners can diagnose collapse before it fully sets in. Methods like BYOL that lack explicit negative terms are especially vulnerable to silent collapse — monitoring uniformity reveals this immediately."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\n\nclass CollapseMonitor:\n    \"\"\"Track alignment and uniformity across training to detect collapse.\"\"\"\n\n    def __init__(self, window: int = 50):\n        self.window = window\n        self.align_history   = []\n        self.uniform_history = []\n\n    def update(self, z1: torch.Tensor, z2: torch.Tensor):\n        with torch.no_grad():\n            z1n = F.normalize(z1.detach(), dim=1)\n            z2n = F.normalize(z2.detach(), dim=1)\n            align   = (z1n - z2n).norm(dim=1).pow(2).mean().item()\n            sq_dist = 2 - 2 * (z1n @ z1n.T)\n            uniform = torch.exp(-2 * sq_dist).mean().log().item()\n        self.align_history.append(align)\n        self.uniform_history.append(uniform)\n\n    def is_collapsing(self, align_thresh: float = 0.05,\n                      uniform_thresh: float = -0.5) -\u003e bool:\n        if len(self.align_history) \u003c self.window:\n            return False\n        recent_align   = sum(self.align_history[-self.window:]) / self.window\n        recent_uniform = sum(self.uniform_history[-self.window:]) / self.window\n        return recent_align \u003c align_thresh and recent_uniform \u003e uniform_thresh\n\n    def report(self):\n        if self.align_history:\n            print(f\u0027Alignment:   {self.align_history[-1]:.4f} (lower=more aligned)\u0027)\n            print(f\u0027Uniformity:  {self.uniform_history[-1]:.4f} (more negative=more uniform)\u0027)\n            print(f\u0027Collapsing:  {self.is_collapsing()}\u0027)\n\n\nmonitor = CollapseMonitor()\ntorch.manual_seed(0)\nz1 = F.normalize(torch.randn(64, 128), dim=1)\nz2 = F.normalize(torch.randn(64, 128), dim=1)\nfor _ in range(55):\n    monitor.update(z1, z2)\nmonitor.report()"},{"type":"callout","variant":"warning","title":"Collapse Is Silent Without Uniformity Tracking","content":"Methods without explicit negative terms (BYOL, SimSiam, JEPA) are at risk of representational collapse — all embeddings converge to the same point. The loss may appear to decrease even as collapse progresses because alignment improves. Monitoring the uniformity metric separately is the most reliable early warning. If uniformity rises toward 0 while alignment falls toward 0, collapse is imminent. Good training shows both metrics improving: alignment decreasing and uniformity becoming more negative."},{"type":"heading","level":2,"content":"Information-Theoretic Interpretation"},{"type":"text","content":"Uniformity on the hypersphere is connected to differential entropy. The uniform distribution on the sphere has maximum entropy among all distributions with unit-norm support — it is the maximum-entropy distribution under the constraint that features are L2-normalised. Maximising uniformity is therefore equivalent to maximising the entropy of the feature distribution, which in turn maximises the mutual information between features and input — the information bottleneck perspective on representation learning. Alignment simultaneously minimises the entropy of the conditional feature distribution given the augmented view."},{"type":"list","ordered":false,"items":["Uniformity = maximum entropy principle on unit sphere = maximum information in feature distribution.","Alignment = minimum entropy of conditional distribution p(f(x\u0027)|f(x)) — invariance to nuisance.","Optimal representation: perfect alignment with maximum uniformity (zero redundancy, zero collapse).","In practice: these two objectives compete — they must be balanced by the loss weighting.","NT-Xent temperature τ: lower τ increases gradient on hard negatives, stronger uniformity push.","Barlow Twins / VICReg achieve uniformity differently — via cross-correlation or variance penalties."]},{"type":"heading","level":2,"content":"Comparison Across SSL Methods"},{"type":"table","headers":["Method","Alignment Mechanism","Uniformity Mechanism","Collapse Prevention","Needs Negatives"],"rows":[["SimCLR","Positive pair similarity maximisation","In-batch negatives repulsion","Implicit (large batch)","Yes"],["BYOL","Online → target network MSE","None explicit","EMA + predictor asymmetry","No"],["Barlow Twins","Cross-correlation diagonal = 1","Off-diagonal cross-correlation = 0","Redundancy reduction","No"],["VICReg","Positive pair MSE","Variance regulariser per dim","Explicit variance term","No"],["DINO","CLS token cross-entropy match","Centering + sharpening (Sinkhorn)","Centering prevents collapse","No"]]},{"type":"text","content":"The alignment/uniformity framework reveals that methods without negatives (BYOL, Barlow Twins, VICReg, DINO) are not avoiding the fundamental tradeoff — they are implementing uniformity through different mechanisms. BYOL relies on the EMA asymmetry to implicitly spread features; Barlow Twins uses cross-correlation off-diagonal penalty; VICReg adds an explicit variance term per embedding dimension. All are geometric regularisers on the hypersphere, achieveing the same purpose as explicit negatives but through architectural or loss engineering."},{"type":"heading","level":2,"content":"Practical Guidance for SSL Training"},{"type":"text","content":"Log both alignment and uniformity every 100 steps during training. A healthy training run shows alignment decreasing from ~2.0 toward ~0.1 and uniformity becoming more negative (from near 0 toward -4.0 or lower) as features spread. If alignment decreases but uniformity stagnates, increase batch size or add stronger augmentation to provide more diverse negatives. If uniformity improves but alignment remains high, the augmentations may be too aggressive or the positive pairs are not consistently similar. Temperature τ is the primary knob for the uniformity–alignment tradeoff in contrastive methods: lower τ increases the uniformity gradient at the cost of harder positive alignment."}]"
---
# Uniformity and Alignment — Geometric Theory of Contrastive Learning

Wang and Isola (2020) offered one of the clearest theoretical frameworks for understanding why contrastive learning works. They showed that contrastive loss on the unit hypersphere can be decomposed into two competing geometric properties: alignment (positive pairs should be close together) and uniformity (all features should be spread as uniformly as possible across the sphere). These two properties are not arbitrary — they correspond to an ideal representation that is maximally informative: positive pairs agree (alignment) and the entire feature space is used without collapse (uniformity).

## Alignment — Attracting Positive Pairs

Alignment measures how well the encoder maps semantically similar inputs to nearby representations. For a distribution of positive pairs (x, x') drawn from the same image with different augmentations, the alignment loss is the expected squared Euclidean distance between their L2-normalised representations: L_align = E_{(x,x')~p_pos}[‖f(x) − f(x')‖²]. For unit-norm vectors, this equals 2(1 − cosine_similarity(f(x), f(x'))). Perfect alignment (L_align = 0) means the encoder is invariant to augmentation — both views map to the exact same point. This is the simplest form of representation learning: invariance to nuisance variation.

```python
import torch
import torch.nn.functional as F


def alignment_loss(z1: torch.Tensor, z2: torch.Tensor, alpha: float = 2.0) -> torch.Tensor:
    """Alignment loss: expected ||f(x) - f(x')||^alpha for positive pairs.
    z1, z2: (N, D) L2-normalised embeddings of two augmented views.
    alpha=2 gives squared Euclidean distance on unit sphere.
    """
    z1 = F.normalize(z1, dim=1)  # ensure unit norm
    z2 = F.normalize(z2, dim=1)
    return (z1 - z2).norm(dim=1).pow(alpha).mean()


def alignment_via_cosine(z1: torch.Tensor, z2: torch.Tensor) -> torch.Tensor:
    """Equivalent: L_align = 2 * (1 - mean cosine similarity)."""
    z1 = F.normalize(z1, dim=1)
    z2 = F.normalize(z2, dim=1)
    cos_sim = (z1 * z2).sum(dim=1)   # (N,) cosine similarity per pair
    return 2 * (1 - cos_sim.mean())


# Demo: perfect alignment, random alignment, collapsed alignment
torch.manual_seed(42)
z = F.normalize(torch.randn(64, 128), dim=1)
print('Perfect alignment (z1 == z2):  ', alignment_loss(z, z).item())          # 0.0

z2_rand = F.normalize(torch.randn(64, 128), dim=1)
print('Random alignment:               ', alignment_loss(z, z2_rand).item())   # ~2.0

z2_noise = F.normalize(z + 0.05 * torch.randn_like(z), dim=1)
print('Near-perfect alignment (noise):', alignment_loss(z, z2_noise).item())   # small
```

## Uniformity — Spreading Features on the Hypersphere

Uniformity measures how evenly the encoder's output distribution covers the unit hypersphere. A completely uniform distribution maximises entropy — every dimension is used and no information is wasted. The uniformity loss uses a Gaussian kernel to measure the average pairwise similarity: L_uniform = log E_{x,y~p_data}[e^{-2‖f(x)−f(y)‖²}]. The Gaussian kernel e^{-2‖u−v‖²} decays from 1 (when u = v) to 0 (when u and v are orthogonal). The log ensures the scale is additive. Minimising L_uniform pushes features apart — the optimal solution is a uniform distribution on the sphere (a perfectly spread packing).

```python
import torch
import torch.nn.functional as F


def uniformity_loss(z: torch.Tensor, t: float = 2.0) -> torch.Tensor:
    """Uniformity loss: log-average of Gaussian kernel over all pairs.
    z: (N, D) L2-normalised embeddings.
    t: Gaussian kernel bandwidth (default 2 gives e^{-2||u-v||^2}).
    """
    z = F.normalize(z, dim=1)                        # (N, D)
    # Pairwise squared distances: ||u-v||^2 = 2 - 2*u.v for unit vectors
    sq_dists = 2 - 2 * (z @ z.T)                    # (N, N)
    # Gaussian kernel; include all pairs (diagonal = self, contributes 1)
    kernel   = torch.exp(-t * sq_dists)              # (N, N)
    # Log average over all N^2 pairs
    return kernel.mean().log()


# Demo: collapsed (all same) vs uniform (random unit vectors)
torch.manual_seed(0)
N, D = 256, 128

# Collapsed: all embeddings identical
z_collapsed = F.normalize(torch.ones(N, D), dim=1)
print('Uniformity (collapsed):', uniformity_loss(z_collapsed).item())   # near 0 (bad)

# Random unit vectors approximate uniform distribution
z_uniform = F.normalize(torch.randn(N, D), dim=1)
print('Uniformity (random):   ', uniformity_loss(z_uniform).item())     # very negative (good)

# Slight cluster structure
z_mixed = F.normalize(torch.randn(N, D) * 0.5 + torch.randn(1, D), dim=1)
print('Uniformity (clustered):', uniformity_loss(z_mixed).item())       # between
```

## NT-Xent as Alignment Plus Uniformity

Wang and Isola proved that the NT-Xent loss (used by SimCLR) asymptotically decomposes into the alignment and uniformity terms. The numerator of NT-Xent maximises the similarity of positive pairs — this is the alignment term. The denominator normalises against all pairs including negatives — this is the uniformity term (pushing features apart). As batch size → ∞, NT-Xent = −alignment_term + uniformity_constant. This decomposition shows that NT-Xent implicitly optimises both geometric properties simultaneously, explaining why it generalises beyond its original contrastive framing.

```python
import torch
import torch.nn.functional as F


def nt_xent_decomposed(z1: torch.Tensor, z2: torch.Tensor,
                       temperature: float = 0.5) -> dict:
    """Compute NT-Xent and its alignment + uniformity decomposition.
    z1, z2: (N, D) L2-normalised embeddings.
    Returns dict with total loss, alignment component, uniformity component.
    """
    N = z1.size(0)
    z1 = F.normalize(z1, dim=1)
    z2 = F.normalize(z2, dim=1)
    z  = torch.cat([z1, z2], dim=0)   # (2N, D)

    # NT-Xent total loss
    sim_mat = (z @ z.T) / temperature   # (2N, 2N)
    mask    = torch.eye(2*N, dtype=torch.bool, device=z.device)
    sim_mat.masked_fill_(mask, float('-inf'))
    labels  = torch.cat([torch.arange(N, 2*N), torch.arange(N)]).to(z.device)
    nt_xent = F.cross_entropy(sim_mat, labels)

    # Alignment component (log numerator, normalised)
    pos_sim = (z1 * z2).sum(dim=1) / temperature   # (N,)
    align   = -pos_sim.mean()

    # Uniformity component (log denominator, approximation)
    uniform = uniformity_loss(z, t=2.0)

    return {'nt_xent': nt_xent.item(), 'alignment': align.item(), 'uniformity': uniform.item()}


torch.manual_seed(7)
z1 = F.normalize(torch.randn(128, 64), dim=1)
z2 = F.normalize(torch.randn(128, 64), dim=1)
result = nt_xent_decomposed(z1, z2)
for k, v in result.items():
    print(f'{k:>12}: {v:.4f}')
```

## Collapse Detection During Training

One of the most practical applications of the alignment/uniformity decomposition is early collapse detection. Representational collapse — where the encoder maps all inputs to the same point — produces perfect alignment (L_align ≈ 0) but maximally bad uniformity (L_uniform ≈ 0, since the Gaussian kernel for identical vectors is 1, and log(1) = 0). By tracking both metrics independently during training, practitioners can diagnose collapse before it fully sets in. Methods like BYOL that lack explicit negative terms are especially vulnerable to silent collapse — monitoring uniformity reveals this immediately.

```python
import torch
import torch.nn.functional as F


class CollapseMonitor:
    """Track alignment and uniformity across training to detect collapse."""

    def __init__(self, window: int = 50):
        self.window = window
        self.align_history   = []
        self.uniform_history = []

    def update(self, z1: torch.Tensor, z2: torch.Tensor):
        with torch.no_grad():
            z1n = F.normalize(z1.detach(), dim=1)
            z2n = F.normalize(z2.detach(), dim=1)
            align   = (z1n - z2n).norm(dim=1).pow(2).mean().item()
            sq_dist = 2 - 2 * (z1n @ z1n.T)
            uniform = torch.exp(-2 * sq_dist).mean().log().item()
        self.align_history.append(align)
        self.uniform_history.append(uniform)

    def is_collapsing(self, align_thresh: float = 0.05,
                      uniform_thresh: float = -0.5) -> bool:
        if len(self.align_history) < self.window:
            return False
        recent_align   = sum(self.align_history[-self.window:]) / self.window
        recent_uniform = sum(self.uniform_history[-self.window:]) / self.window
        return recent_align < align_thresh and recent_uniform > uniform_thresh

    def report(self):
        if self.align_history:
            print(f'Alignment:   {self.align_history[-1]:.4f} (lower=more aligned)')
            print(f'Uniformity:  {self.uniform_history[-1]:.4f} (more negative=more uniform)')
            print(f'Collapsing:  {self.is_collapsing()}')


monitor = CollapseMonitor()
torch.manual_seed(0)
z1 = F.normalize(torch.randn(64, 128), dim=1)
z2 = F.normalize(torch.randn(64, 128), dim=1)
for _ in range(55):
    monitor.update(z1, z2)
monitor.report()
```

> **Collapse Is Silent Without Uniformity Tracking**: Methods without explicit negative terms (BYOL, SimSiam, JEPA) are at risk of representational collapse — all embeddings converge to the same point. The loss may appear to decrease even as collapse progresses because alignment improves. Monitoring the uniformity metric separately is the most reliable early warning. If uniformity rises toward 0 while alignment falls toward 0, collapse is imminent. Good training shows both metrics improving: alignment decreasing and uniformity becoming more negative.

## Information-Theoretic Interpretation

Uniformity on the hypersphere is connected to differential entropy. The uniform distribution on the sphere has maximum entropy among all distributions with unit-norm support — it is the maximum-entropy distribution under the constraint that features are L2-normalised. Maximising uniformity is therefore equivalent to maximising the entropy of the feature distribution, which in turn maximises the mutual information between features and input — the information bottleneck perspective on representation learning. Alignment simultaneously minimises the entropy of the conditional feature distribution given the augmented view.

- Uniformity = maximum entropy principle on unit sphere = maximum information in feature distribution.
- Alignment = minimum entropy of conditional distribution p(f(x')|f(x)) — invariance to nuisance.
- Optimal representation: perfect alignment with maximum uniformity (zero redundancy, zero collapse).
- In practice: these two objectives compete — they must be balanced by the loss weighting.
- NT-Xent temperature τ: lower τ increases gradient on hard negatives, stronger uniformity push.
- Barlow Twins / VICReg achieve uniformity differently — via cross-correlation or variance penalties.

## Comparison Across SSL Methods

| Method | Alignment Mechanism | Uniformity Mechanism | Collapse Prevention | Needs Negatives |
| --- | --- | --- | --- | --- |
| SimCLR | Positive pair similarity maximisation | In-batch negatives repulsion | Implicit (large batch) | Yes |
| BYOL | Online → target network MSE | None explicit | EMA + predictor asymmetry | No |
| Barlow Twins | Cross-correlation diagonal = 1 | Off-diagonal cross-correlation = 0 | Redundancy reduction | No |
| VICReg | Positive pair MSE | Variance regulariser per dim | Explicit variance term | No |
| DINO | CLS token cross-entropy match | Centering + sharpening (Sinkhorn) | Centering prevents collapse | No |

The alignment/uniformity framework reveals that methods without negatives (BYOL, Barlow Twins, VICReg, DINO) are not avoiding the fundamental tradeoff — they are implementing uniformity through different mechanisms. BYOL relies on the EMA asymmetry to implicitly spread features; Barlow Twins uses cross-correlation off-diagonal penalty; VICReg adds an explicit variance term per embedding dimension. All are geometric regularisers on the hypersphere, achieveing the same purpose as explicit negatives but through architectural or loss engineering.

## Practical Guidance for SSL Training

Log both alignment and uniformity every 100 steps during training. A healthy training run shows alignment decreasing from ~2.0 toward ~0.1 and uniformity becoming more negative (from near 0 toward -4.0 or lower) as features spread. If alignment decreases but uniformity stagnates, increase batch size or add stronger augmentation to provide more diverse negatives. If uniformity improves but alignment remains high, the augmentations may be too aggressive or the positive pairs are not consistently similar. Temperature τ is the primary knob for the uniformity–alignment tradeoff in contrastive methods: lower τ increases the uniformity gradient at the cost of harder positive alignment.

