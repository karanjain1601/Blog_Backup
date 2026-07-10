---
title: "Barlow Twins — Cross-Correlation Matrix and Redundancy Reduction"
slug: "barlow-twins"
description: "Barlow Twins (Zbontar et al. 2021) avoids representational collapse by enforcing the cross-correlation matrix between embeddings of two augmented views to be close to the identity matrix, simultaneously making features invariant and decorrelated."
tags: ["deep-learning", "self-supervised-learning", "contrastive-learning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Barlow Twins (Zbontar et al. 2021) takes a fundamentally different approach to self-supervised learning. Rather than using a contrastive loss over negative pairs or an asymmetric predictor, it directly regularises the statistics of the representations. The objective is to make the cross-correlation matrix C between embeddings of two augmented views as close as possible to the identity matrix — simultaneously maximising invariance to augmentations and minimising redundancy between embedding dimensions."},{"type":"heading","level":2,"content":"Redundancy Reduction Principle"},{"type":"text","content":"The name references Horace Barlow\u0027s redundancy-reduction principle from neuroscience (1961): an efficient neural code should minimise statistical dependencies between neurons. In the context of representation learning, this means the dimensions of the embedding vector should be decorrelated. If two dimensions are highly correlated, they carry redundant information — the network is wasting capacity. Barlow Twins enforces decorrelation through the off-diagonal terms of the cross-correlation matrix."},{"type":"heading","level":2,"content":"Cross-Correlation Matrix and Loss"},{"type":"text","content":"For a batch of N images producing normalised embeddings Z^A, Z^B ∈ ℝ^{N×D} (one per augmented view, normalised along the batch dimension), the cross-correlation matrix is C ∈ ℝ^{D×D} with Cᵢⱼ = Σₙ z^A_{n,i} z^B_{n,j} / N. The loss has two terms: invariance term Σᵢ(1-Cᵢᵢ)² forces diagonal to 1 (each feature invariant); redundancy reduction term λΣᵢΣⱼ≠ᵢ Cᵢⱼ² forces off-diagonal to 0 (features decorrelated). λ controls the trade-off (λ=0.005 in the paper)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef barlow_twins_loss(z_a, z_b, lambda_coeff=0.005):\n    \"\"\"Barlow Twins loss.\n    z_a, z_b: (N, D) embeddings from two augmented views (NOT yet normalised).\n    lambda_coeff: weight for redundancy-reduction (off-diagonal) term.\n    \"\"\"\n    N, D = z_a.size()\n    # Normalise along batch dimension (not feature dimension)\n    z_a_norm = (z_a - z_a.mean(0)) / (z_a.std(0) + 1e-6)  # (N, D)\n    z_b_norm = (z_b - z_b.mean(0)) / (z_b.std(0) + 1e-6)\n    # Cross-correlation matrix: C = Z_a^T @ Z_b / N  →  (D, D)\n    C = z_a_norm.T @ z_b_norm / N\n    # Invariance loss: (diagonal → 1)\n    on_diag  = (1 - C.diagonal()).pow(2).sum()\n    # Redundancy-reduction loss: (off-diagonal → 0)\n    off_diag = off_diagonal(C).pow(2).sum()\n    return on_diag + lambda_coeff * off_diag\n\ndef off_diagonal(C):\n    \"\"\"Return all off-diagonal elements of a square matrix as a 1D tensor.\"\"\"\n    n = C.size(0)\n    return C.flatten()[:-1].view(n-1, n+1)[:, 1:].flatten()\n\n# Test\ntorch.manual_seed(0)\nz_a = torch.randn(256, 8192)\nz_b = torch.randn(256, 8192)\nloss = barlow_twins_loss(z_a, z_b)\nprint(f\u0027Barlow Twins loss (random embeddings, D=8192): {loss.item():.2f}\u0027)\n# With identical embeddings, diagonal=1 so on_diag=0; off-diag still penalised\nz_same = torch.randn(256, 8192)\nloss_same = barlow_twins_loss(z_same, z_same)\nprint(f\u0027Barlow Twins loss (identical views, D=8192): {loss_same.item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Training Loop"},{"type":"text","content":"The Barlow Twins training loop is symmetric: both views pass through the same encoder and projector, and the loss is computed once (not symmetrised over both orderings, because C and Cᵀ both appear implicitly). No stop-gradient is needed — the loss gradient naturally flows through both branches. The key design choice is the high-dimensional projection head: projecting to 8192 dimensions (vs 128 in SimCLR) is beneficial because the D×D cross-correlation matrix has more degrees of freedom to capture redundancy."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport torchvision.models as models\n\nclass BarlowTwins(nn.Module):\n    def __init__(self, backbone_fn=models.resnet50, proj_dim=8192, lambda_coeff=0.005):\n        super().__init__()\n        self.lambda_coeff = lambda_coeff\n        base = backbone_fn(weights=None)\n        feat_dim = base.fc.in_features  # 2048\n        self.encoder = nn.Sequential(*list(base.children())[:-1])\n        # Projector: 3-layer MLP to high-dimensional space\n        self.projector = nn.Sequential(\n            nn.Linear(feat_dim, 8192, bias=False), nn.BatchNorm1d(8192), nn.ReLU(),\n            nn.Linear(8192, 8192, bias=False), nn.BatchNorm1d(8192), nn.ReLU(),\n            nn.Linear(8192, proj_dim, bias=False),\n        )\n\n    def forward(self, x1, x2):\n        z1 = self.projector(self.encoder(x1).flatten(1))  # (N, 8192)\n        z2 = self.projector(self.encoder(x2).flatten(1))\n        loss = barlow_twins_loss(z1, z2, self.lambda_coeff)\n        return loss\n\n# Training step\ndef train_step(model, batch, optimizer):\n    (view1, view2), _ = batch\n    view1, view2 = view1.cuda(), view2.cuda()\n    loss = model(view1, view2)\n    optimizer.zero_grad()\n    loss.backward()\n    optimizer.step()\n    return loss.item()\n\nmodel = BarlowTwins()\nprint(\u0027BarlowTwins parameters:\u0027, sum(p.numel() for p in model.parameters()) // 1_000_000, \u0027M\u0027)\nprint(\u0027Projector output dim: 8192 — much larger than SimCLR (128)\u0027)"},{"type":"heading","level":2,"content":"Visualising the Cross-Correlation Matrix"},{"type":"text","content":"A well-trained Barlow Twins model should produce a cross-correlation matrix that approaches the identity: diagonal entries near 1.0 and off-diagonal entries near 0.0. Monitoring this matrix during training gives insight into the quality of representations. If the diagonal entries are low, the invariance term is not satisfied — the encoder is not producing augmentation-invariant features. If the off-diagonal entries are high, the redundancy-reduction is failing."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport numpy as np\n\ndef compute_cross_correlation(z_a, z_b):\n    \"\"\"Compute cross-correlation matrix between two batches of embeddings.\"\"\"\n    N = z_a.size(0)\n    z_a_norm = (z_a - z_a.mean(0)) / (z_a.std(0) + 1e-6)\n    z_b_norm = (z_b - z_b.mean(0)) / (z_b.std(0) + 1e-6)\n    return (z_a_norm.T @ z_b_norm / N).detach().cpu()\n\ndef analyse_cc_matrix(C):\n    \"\"\"Report statistics of a cross-correlation matrix.\"\"\"\n    D = C.size(0)\n    diag = C.diagonal()\n    mask = ~torch.eye(D, dtype=torch.bool)\n    off  = C[mask]\n    print(f\u0027Diagonal  — mean: {diag.mean():.4f}, std: {diag.std():.4f}\u0027)\n    print(f\u0027Off-diag  — mean: {off.mean():.4f},  std: {off.std():.4f}\u0027)\n    print(f\u0027Frobenius distance to identity: {(C - torch.eye(D)).norm():.4f}\u0027)\n\ntorch.manual_seed(42)\nD = 64\n# Simulate an untrained model (random embeddings)\nC_random = compute_cross_correlation(torch.randn(512, D), torch.randn(512, D))\nprint(\u0027--- Untrained (random) ---\u0027)\nanalyse_cc_matrix(C_random)\n\n# Simulate a well-trained model (same embeddings, decorrelated)\nz = torch.linalg.qr(torch.randn(512, D))[0] * (512 ** 0.5)  # orthonormal rows\nC_trained = compute_cross_correlation(z, z + 0.1 * torch.randn_like(z))\nprint(\u0027--- Near-ideal model ---\u0027)\nanalyse_cc_matrix(C_trained)"},{"type":"heading","level":2,"content":"High-Dimensional Projection Head"},{"type":"text","content":"A surprising finding of Barlow Twins is that projecting to very high dimensions (8192 vs SimCLR\u0027s 128) significantly improves performance. The intuition is that the cross-correlation matrix C ∈ ℝ^{D×D} grows quadratically with D, providing D² constraints for the optimiser to work with. At D = 128, the matrix has only ~16K entries; at D = 8192, ~67M entries, providing a much richer signal. This is unlike SimCLR where higher projection dimension yields diminishing returns."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef build_barlow_projector(in_dim=2048, hidden_dim=8192, out_dim=8192):\n    \"\"\"High-dimensional 3-layer MLP projector for Barlow Twins.\"\"\"\n    return nn.Sequential(\n        nn.Linear(in_dim, hidden_dim, bias=False),\n        nn.BatchNorm1d(hidden_dim),\n        nn.ReLU(inplace=True),\n        nn.Linear(hidden_dim, hidden_dim, bias=False),\n        nn.BatchNorm1d(hidden_dim),\n        nn.ReLU(inplace=True),\n        nn.Linear(hidden_dim, out_dim, bias=False),\n        # No BN on final layer — raw outputs for cross-correlation normalisation\n    )\n\n# Compare parameter counts across projection dimensions\nfor dim in [128, 512, 2048, 8192]:\n    proj = build_barlow_projector(out_dim=dim)\n    params = sum(p.numel() for p in proj.parameters()) // 1000\n    n_matrix_entries = dim * dim\n    print(f\u0027  D={dim:5d}: proj_params={params:6d}K,  \u0027\n          f\u0027CC matrix entries={n_matrix_entries:9d},  \u0027\n          f\u0027off-diagonal constraints={n_matrix_entries - dim:9d}\u0027)"},{"type":"callout","variant":"info","title":"λ Controls Invariance vs Redundancy Trade-off","content":"The λ coefficient (default 0.005) weights the off-diagonal redundancy term relative to the diagonal invariance term. A small λ emphasises invariance (diagonal → 1) but allows correlated dimensions. A large λ aggressively decorrelates features but may sacrifice invariance. In practice, λ is sensitive to the projection dimensionality: larger D often needs smaller λ since the off-diagonal sum grows as O(D²) while the diagonal sum grows as O(D)."},{"type":"heading","level":2,"content":"Connection to Information Theory"},{"type":"text","content":"Barlow Twins has a direct connection to information-theoretic principles. Maximising the diagonal of C (invariance) maximises mutual information between the two views — the representations should carry the same content despite different augmentations. Minimising the off-diagonal (redundancy reduction) implements a whitening-like objective that spreads information evenly across dimensions. Together, these objectives resemble maximising the joint entropy of the embedding while constraining mutual information between dimensions."},{"type":"list","ordered":false,"items":["Barlow\u0027s redundancy-reduction: efficient neural codes decorrelate outputs (neuroscience, 1961).","λ=0.005 works across scales; tune if D changes significantly from 8192.","Training: LARS optimiser, batch 2048, lr=0.2, weight_decay=1.5e-6, 1000 epochs.","Projection normalised along batch dim (not feature dim) — unlike SimCLR\u0027s L2 normalisation.","No stop-gradient needed: the cross-correlation loss naturally prevents collapse."]},{"type":"table","headers":["Method","Loss Mechanism","Negatives","Proj Dim","Linear Eval Top-1","Key Innovation"],"rows":[["Barlow Twins","Cross-corr → identity","No","8192","73.2%","Redundancy reduction via off-diagonal penalty"],["VICReg","Var + Inv + Cov","No","8192","73.2%","Explicit variance term prevents collapse"],["SimCLR v1","NT-Xent contrastive","Yes","128","69.3%","Large batch in-batch negatives"],["BYOL","MSE (normalised)","No","256","74.3%","EMA target + predictor asymmetry"]]},{"type":"heading","level":2,"content":"Practical Considerations and Tuning"},{"type":"text","content":"Barlow Twins is straightforward to implement but has a few practical pitfalls. The cross-correlation matrix computation scales as O(N·D²) in memory for a D-dimensional embedding — at D=8192 and N=2048, the matrix itself is 8192×8192 = 67M float32 values (~256 MB). This is manageable on a single GPU but requires care. The off_diagonal helper function must correctly exclude the D diagonal elements. Batch normalisation in the projector (but not on the final output layer) is important for training stability; omitting it causes the cross-correlation matrix to be ill-conditioned."}]"
---
# Barlow Twins — Cross-Correlation Matrix and Redundancy Reduction

Barlow Twins (Zbontar et al. 2021) takes a fundamentally different approach to self-supervised learning. Rather than using a contrastive loss over negative pairs or an asymmetric predictor, it directly regularises the statistics of the representations. The objective is to make the cross-correlation matrix C between embeddings of two augmented views as close as possible to the identity matrix — simultaneously maximising invariance to augmentations and minimising redundancy between embedding dimensions.

## Redundancy Reduction Principle

The name references Horace Barlow's redundancy-reduction principle from neuroscience (1961): an efficient neural code should minimise statistical dependencies between neurons. In the context of representation learning, this means the dimensions of the embedding vector should be decorrelated. If two dimensions are highly correlated, they carry redundant information — the network is wasting capacity. Barlow Twins enforces decorrelation through the off-diagonal terms of the cross-correlation matrix.

## Cross-Correlation Matrix and Loss

For a batch of N images producing normalised embeddings Z^A, Z^B ∈ ℝ^{N×D} (one per augmented view, normalised along the batch dimension), the cross-correlation matrix is C ∈ ℝ^{D×D} with Cᵢⱼ = Σₙ z^A_{n,i} z^B_{n,j} / N. The loss has two terms: invariance term Σᵢ(1-Cᵢᵢ)² forces diagonal to 1 (each feature invariant); redundancy reduction term λΣᵢΣⱼ≠ᵢ Cᵢⱼ² forces off-diagonal to 0 (features decorrelated). λ controls the trade-off (λ=0.005 in the paper).

```python
import torch
import torch.nn.functional as F

def barlow_twins_loss(z_a, z_b, lambda_coeff=0.005):
    """Barlow Twins loss.
    z_a, z_b: (N, D) embeddings from two augmented views (NOT yet normalised).
    lambda_coeff: weight for redundancy-reduction (off-diagonal) term.
    """
    N, D = z_a.size()
    # Normalise along batch dimension (not feature dimension)
    z_a_norm = (z_a - z_a.mean(0)) / (z_a.std(0) + 1e-6)  # (N, D)
    z_b_norm = (z_b - z_b.mean(0)) / (z_b.std(0) + 1e-6)
    # Cross-correlation matrix: C = Z_a^T @ Z_b / N  →  (D, D)
    C = z_a_norm.T @ z_b_norm / N
    # Invariance loss: (diagonal → 1)
    on_diag  = (1 - C.diagonal()).pow(2).sum()
    # Redundancy-reduction loss: (off-diagonal → 0)
    off_diag = off_diagonal(C).pow(2).sum()
    return on_diag + lambda_coeff * off_diag

def off_diagonal(C):
    """Return all off-diagonal elements of a square matrix as a 1D tensor."""
    n = C.size(0)
    return C.flatten()[:-1].view(n-1, n+1)[:, 1:].flatten()

# Test
torch.manual_seed(0)
z_a = torch.randn(256, 8192)
z_b = torch.randn(256, 8192)
loss = barlow_twins_loss(z_a, z_b)
print(f'Barlow Twins loss (random embeddings, D=8192): {loss.item():.2f}')
# With identical embeddings, diagonal=1 so on_diag=0; off-diag still penalised
z_same = torch.randn(256, 8192)
loss_same = barlow_twins_loss(z_same, z_same)
print(f'Barlow Twins loss (identical views, D=8192): {loss_same.item():.4f}')
```

## Training Loop

The Barlow Twins training loop is symmetric: both views pass through the same encoder and projector, and the loss is computed once (not symmetrised over both orderings, because C and Cᵀ both appear implicitly). No stop-gradient is needed — the loss gradient naturally flows through both branches. The key design choice is the high-dimensional projection head: projecting to 8192 dimensions (vs 128 in SimCLR) is beneficial because the D×D cross-correlation matrix has more degrees of freedom to capture redundancy.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import torchvision.models as models

class BarlowTwins(nn.Module):
    def __init__(self, backbone_fn=models.resnet50, proj_dim=8192, lambda_coeff=0.005):
        super().__init__()
        self.lambda_coeff = lambda_coeff
        base = backbone_fn(weights=None)
        feat_dim = base.fc.in_features  # 2048
        self.encoder = nn.Sequential(*list(base.children())[:-1])
        # Projector: 3-layer MLP to high-dimensional space
        self.projector = nn.Sequential(
            nn.Linear(feat_dim, 8192, bias=False), nn.BatchNorm1d(8192), nn.ReLU(),
            nn.Linear(8192, 8192, bias=False), nn.BatchNorm1d(8192), nn.ReLU(),
            nn.Linear(8192, proj_dim, bias=False),
        )

    def forward(self, x1, x2):
        z1 = self.projector(self.encoder(x1).flatten(1))  # (N, 8192)
        z2 = self.projector(self.encoder(x2).flatten(1))
        loss = barlow_twins_loss(z1, z2, self.lambda_coeff)
        return loss

# Training step
def train_step(model, batch, optimizer):
    (view1, view2), _ = batch
    view1, view2 = view1.cuda(), view2.cuda()
    loss = model(view1, view2)
    optimizer.zero_grad()
    loss.backward()
    optimizer.step()
    return loss.item()

model = BarlowTwins()
print('BarlowTwins parameters:', sum(p.numel() for p in model.parameters()) // 1_000_000, 'M')
print('Projector output dim: 8192 — much larger than SimCLR (128)')
```

## Visualising the Cross-Correlation Matrix

A well-trained Barlow Twins model should produce a cross-correlation matrix that approaches the identity: diagonal entries near 1.0 and off-diagonal entries near 0.0. Monitoring this matrix during training gives insight into the quality of representations. If the diagonal entries are low, the invariance term is not satisfied — the encoder is not producing augmentation-invariant features. If the off-diagonal entries are high, the redundancy-reduction is failing.

```python
import torch
import torch.nn.functional as F
import numpy as np

def compute_cross_correlation(z_a, z_b):
    """Compute cross-correlation matrix between two batches of embeddings."""
    N = z_a.size(0)
    z_a_norm = (z_a - z_a.mean(0)) / (z_a.std(0) + 1e-6)
    z_b_norm = (z_b - z_b.mean(0)) / (z_b.std(0) + 1e-6)
    return (z_a_norm.T @ z_b_norm / N).detach().cpu()

def analyse_cc_matrix(C):
    """Report statistics of a cross-correlation matrix."""
    D = C.size(0)
    diag = C.diagonal()
    mask = ~torch.eye(D, dtype=torch.bool)
    off  = C[mask]
    print(f'Diagonal  — mean: {diag.mean():.4f}, std: {diag.std():.4f}')
    print(f'Off-diag  — mean: {off.mean():.4f},  std: {off.std():.4f}')
    print(f'Frobenius distance to identity: {(C - torch.eye(D)).norm():.4f}')

torch.manual_seed(42)
D = 64
# Simulate an untrained model (random embeddings)
C_random = compute_cross_correlation(torch.randn(512, D), torch.randn(512, D))
print('--- Untrained (random) ---')
analyse_cc_matrix(C_random)

# Simulate a well-trained model (same embeddings, decorrelated)
z = torch.linalg.qr(torch.randn(512, D))[0] * (512 ** 0.5)  # orthonormal rows
C_trained = compute_cross_correlation(z, z + 0.1 * torch.randn_like(z))
print('--- Near-ideal model ---')
analyse_cc_matrix(C_trained)
```

## High-Dimensional Projection Head

A surprising finding of Barlow Twins is that projecting to very high dimensions (8192 vs SimCLR's 128) significantly improves performance. The intuition is that the cross-correlation matrix C ∈ ℝ^{D×D} grows quadratically with D, providing D² constraints for the optimiser to work with. At D = 128, the matrix has only ~16K entries; at D = 8192, ~67M entries, providing a much richer signal. This is unlike SimCLR where higher projection dimension yields diminishing returns.

```python
import torch
import torch.nn as nn

def build_barlow_projector(in_dim=2048, hidden_dim=8192, out_dim=8192):
    """High-dimensional 3-layer MLP projector for Barlow Twins."""
    return nn.Sequential(
        nn.Linear(in_dim, hidden_dim, bias=False),
        nn.BatchNorm1d(hidden_dim),
        nn.ReLU(inplace=True),
        nn.Linear(hidden_dim, hidden_dim, bias=False),
        nn.BatchNorm1d(hidden_dim),
        nn.ReLU(inplace=True),
        nn.Linear(hidden_dim, out_dim, bias=False),
        # No BN on final layer — raw outputs for cross-correlation normalisation
    )

# Compare parameter counts across projection dimensions
for dim in [128, 512, 2048, 8192]:
    proj = build_barlow_projector(out_dim=dim)
    params = sum(p.numel() for p in proj.parameters()) // 1000
    n_matrix_entries = dim * dim
    print(f'  D={dim:5d}: proj_params={params:6d}K,  '
          f'CC matrix entries={n_matrix_entries:9d},  '
          f'off-diagonal constraints={n_matrix_entries - dim:9d}')
```

> **λ Controls Invariance vs Redundancy Trade-off**: The λ coefficient (default 0.005) weights the off-diagonal redundancy term relative to the diagonal invariance term. A small λ emphasises invariance (diagonal → 1) but allows correlated dimensions. A large λ aggressively decorrelates features but may sacrifice invariance. In practice, λ is sensitive to the projection dimensionality: larger D often needs smaller λ since the off-diagonal sum grows as O(D²) while the diagonal sum grows as O(D).

## Connection to Information Theory

Barlow Twins has a direct connection to information-theoretic principles. Maximising the diagonal of C (invariance) maximises mutual information between the two views — the representations should carry the same content despite different augmentations. Minimising the off-diagonal (redundancy reduction) implements a whitening-like objective that spreads information evenly across dimensions. Together, these objectives resemble maximising the joint entropy of the embedding while constraining mutual information between dimensions.

- Barlow's redundancy-reduction: efficient neural codes decorrelate outputs (neuroscience, 1961).
- λ=0.005 works across scales; tune if D changes significantly from 8192.
- Training: LARS optimiser, batch 2048, lr=0.2, weight_decay=1.5e-6, 1000 epochs.
- Projection normalised along batch dim (not feature dim) — unlike SimCLR's L2 normalisation.
- No stop-gradient needed: the cross-correlation loss naturally prevents collapse.

| Method | Loss Mechanism | Negatives | Proj Dim | Linear Eval Top-1 | Key Innovation |
| --- | --- | --- | --- | --- | --- |
| Barlow Twins | Cross-corr → identity | No | 8192 | 73.2% | Redundancy reduction via off-diagonal penalty |
| VICReg | Var + Inv + Cov | No | 8192 | 73.2% | Explicit variance term prevents collapse |
| SimCLR v1 | NT-Xent contrastive | Yes | 128 | 69.3% | Large batch in-batch negatives |
| BYOL | MSE (normalised) | No | 256 | 74.3% | EMA target + predictor asymmetry |

## Practical Considerations and Tuning

Barlow Twins is straightforward to implement but has a few practical pitfalls. The cross-correlation matrix computation scales as O(N·D²) in memory for a D-dimensional embedding — at D=8192 and N=2048, the matrix itself is 8192×8192 = 67M float32 values (~256 MB). This is manageable on a single GPU but requires care. The off_diagonal helper function must correctly exclude the D diagonal elements. Batch normalisation in the projector (but not on the final output layer) is important for training stability; omitting it causes the cross-correlation matrix to be ill-conditioned.

