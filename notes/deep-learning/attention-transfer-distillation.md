---
title: "Attention Transfer — Spatial Attention Map Distillation"
slug: "attention-transfer-distillation"
description: "Transfer where the teacher looks by matching spatial attention maps computed from intermediate feature tensors. Covers sum-squared and max attention maps, multi-stage AT loss, gradient-based attention, combined AT and logit KD training, and SemCKD cross-layer attention transfer."
tags: ["deep-learning", "model-compression", "knowledge-distillation"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Attention Transfer (Zagoruyko \u0026 Komodakis 2017) distills not what the teacher knows but where it looks. A well-trained teacher has learned to focus on discriminative regions — the animal\u0027s face rather than the background, the wheel arch rather than the car door. The student should look at those same regions. AT computes a spatial attention map from each intermediate feature tensor and penalizes the student for looking at different regions than the teacher."},{"type":"heading","level":2,"content":"Attention Map Computation: Sum, Max, and L2"},{"type":"text","content":"Given a feature tensor F ∈ ℝ^{C×H×W}, three attention map variants are commonly used. Sum-squared (default AT): A_sum = Σ_c F_k² — sum of squared activations over channels, producing a (H×W) heatmap. Max absolute: A_max = max_c |F_k| — maximum absolute activation over channels. L2 norm: A_l2 = ‖F_k‖_2 over channels. All maps are normalized by their Frobenius norm: Ā = A / ‖A‖_F. The sum-squared variant is the standard choice and performs best in practice."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef compute_attention_maps(feature: torch.Tensor):\n    \"\"\"\n    Compute three attention map variants from F in R^{B x C x H x W}.\n    All maps normalized to unit L2 norm per sample.\n    Returns: (A_sum, A_max, A_l2) each of shape (B, H*W).\n    \"\"\"\n    B, C, H, W = feature.shape\n\n    A_sum = feature.pow(2).sum(dim=1).view(B, -1)       # (B, H*W)\n    A_max = feature.abs().max(dim=1).values.view(B, -1)  # (B, H*W)\n    A_l2  = feature.norm(p=2, dim=1).view(B, -1)         # (B, H*W)\n\n    normalize = lambda A: F.normalize(A, p=2, dim=1)\n    return normalize(A_sum), normalize(A_max), normalize(A_l2)\n\n\ntorch.manual_seed(7)\nB, C, H, W = 4, 128, 8, 8\nfeature = torch.randn(B, C, H, W)\n\nA_sum, A_max, A_l2 = compute_attention_maps(feature)\nprint(f\u0027Feature shape:   {feature.shape}\u0027)\nprint(f\u0027Attention shapes: sum={A_sum.shape}  max={A_max.shape}  l2={A_l2.shape}\u0027)\n\n# Cross-variant correlation (should be high — all capture similar spatial structure)\ncorr_sm = (A_sum * A_max).sum(1).mean().item()\ncorr_sl = (A_sum * A_l2).sum(1).mean().item()\nprint(f\u0027Correlation sum-max: {corr_sm:.4f}   sum-l2: {corr_sl:.4f}\u0027)\nprint(\u0027Sum-of-squares is standard (Zagoruyko \u0026 Komodakis 2017).\u0027)"},{"type":"heading","level":2,"content":"AT Loss at Multiple Intermediate Layers"},{"type":"text","content":"Applying AT at a single layer provides limited supervision. The full AT method applies the loss after each major stage (e.g., after each residual block group in ResNet). This means the student is guided to look in the right places at every level of abstraction — low-level texture regions in early stages, semantic object regions in later stages. The total AT loss is the sum across all paired stages, each weighted by the same β."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef at_map(feature: torch.Tensor) -\u003e torch.Tensor:\n    \"\"\"Sum-of-squared channels attention map, L2-normalized. Shape: (B, H*W).\"\"\"\n    B = feature.shape[0]\n    A = feature.pow(2).sum(dim=1).view(B, -1)\n    return F.normalize(A, p=2, dim=1)\n\nclass MultiStageATLoss(nn.Module):\n    \"\"\"AT loss summed over multiple paired feature map stages.\"\"\"\n\n    def __init__(self, beta: float = 1000.0):\n        super().__init__()\n        self.beta = beta\n\n    def forward(self, student_feats: list, teacher_feats: list) -\u003e torch.Tensor:\n        assert len(student_feats) == len(teacher_feats)\n        device = student_feats[0].device\n        total = torch.zeros(1, device=device)\n        for fs, ft in zip(student_feats, teacher_feats):\n            A_s = at_map(fs)\n            A_t = at_map(ft).detach()\n            if A_s.shape != A_t.shape:  # resample if spatial sizes differ\n                A_t = F.interpolate(A_t.unsqueeze(1),\n                                    size=A_s.shape[-1], mode=\u0027linear\u0027).squeeze(1)\n            total = total + (self.beta / 2.0) * (A_s - A_t).pow(2).mean()\n        return total\n\n\n# Demo: 3-stage ResNet-style feature maps (teacher wider than student)\nB = 4\nstudent_feats = [torch.randn(B,  64, 28, 28),\n                 torch.randn(B, 128, 14, 14),\n                 torch.randn(B, 256,  7,  7)]\nteacher_feats = [torch.randn(B, 128, 28, 28),\n                 torch.randn(B, 256, 14, 14),\n                 torch.randn(B, 512,  7,  7)]\n\nat_loss = MultiStageATLoss(beta=1000.0)\nloss = at_loss(student_feats, teacher_feats)\nprint(f\u0027Multi-stage AT loss (3 stages): {loss.item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Gradient-Based Attention Maps"},{"type":"text","content":"An alternative to activation-based maps is gradient-based attention: the Jacobian of the model\u0027s output with respect to an intermediate feature tensor. ∂y/∂F_k captures how sensitive the final prediction is to each spatial location in layer k — a more informative signal than raw activation magnitudes. GradCAM-style attention combines gradients and activations: A_GradCAM = ReLU(Σ_c (∂y/∂F_c) · F_c). The cost is one additional backward pass per layer; impractical for all layers but effective at a single carefully chosen layer."},{"type":"heading","level":2,"content":"Visualizing Teacher vs Student Attention"},{"type":"text","content":"Before and after AT training, comparing the teacher\u0027s and student\u0027s attention maps reveals whether the student has learned to look at the right image regions. High cosine similarity between the flattened, normalized maps indicates successful attention transfer. In practice, a student trained with AT shows much higher cosine similarity to the teacher\u0027s maps than a student trained with logit KD alone, which explains the accuracy improvement — the student literally focuses on the correct discriminative regions."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport numpy as np\n\ndef attention_heatmap(feature: torch.Tensor) -\u003e np.ndarray:\n    \"\"\"Convert a single-sample feature (C, H, W) to a normalized (H, W) heatmap.\"\"\"\n    A = feature.pow(2).sum(dim=0).detach().cpu().numpy()  # (H, W)\n    return (A - A.min()) / (A.max() - A.min() + 1e-6)\n\ndef compare_attention_maps(teacher_feat: torch.Tensor, student_feat: torch.Tensor):\n    \"\"\"Print statistics comparing teacher and student spatial attention.\"\"\"\n    A_t = attention_heatmap(teacher_feat)\n    A_s = attention_heatmap(student_feat)\n\n    t_flat = A_t.flatten()\n    s_flat = A_s.flatten()\n    cos_sim = np.dot(t_flat, s_flat) / (\n        np.linalg.norm(t_flat) * np.linalg.norm(s_flat) + 1e-6)\n\n    print(f\u0027Teacher attn — mean: {A_t.mean():.4f}  std: {A_t.std():.4f}  max: {A_t.max():.4f}\u0027)\n    print(f\u0027Student attn — mean: {A_s.mean():.4f}  std: {A_s.std():.4f}  max: {A_s.max():.4f}\u0027)\n    print(f\u0027Cosine similarity (teacher vs student): {cos_sim:.4f}\u0027)\n    print(\u0027After AT training, cosine similarity should approach 1.0.\u0027)\n\n\ntorch.manual_seed(3)\nC, H, W = 64, 14, 14\nteacher_feat = torch.randn(C, H, W).abs()  # post-ReLU, non-negative\nstudent_feat = torch.randn(C, H, W).abs()\ncompare_attention_maps(teacher_feat, student_feat)"},{"type":"heading","level":2,"content":"AT + Logit KD Combined Training"},{"type":"text","content":"AT alone without logit KD leaves accuracy on the table. The best results come from combining both: the logit KD term transfers class-level dark knowledge while the AT term aligns spatial attention at every stage. The combined loss is L = α·CE(hard) + (1-α)·T²·KL(soft) + L_AT. Typical weights: α=0.3, β=1000. The AT term is usually unweighted relative to the KD term; its natural scale matches the KD loss without explicit tuning."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport torch.optim as optim\n\ndef at_map(feature):\n    B = feature.shape[0]\n    return F.normalize(feature.pow(2).sum(1).view(B, -1), p=2, dim=1)\n\ndef combined_at_kd_loss(s_logits, t_logits, s_feats, t_feats, labels,\n                         T=4.0, alpha=0.3, beta=1000.0):\n    \"\"\"CE + logit KD + multi-stage AT.\"\"\"\n    hard = F.cross_entropy(s_logits, labels)\n    kd   = F.kl_div(F.log_softmax(s_logits / T, dim=-1),\n                    F.softmax(t_logits / T, dim=-1).detach(),\n                    reduction=\u0027batchmean\u0027) * T ** 2\n    at   = sum((beta / 2.0) * (at_map(fs) - at_map(ft).detach()).pow(2).mean()\n               for fs, ft in zip(s_feats, t_feats))\n    return alpha * hard + (1 - alpha) * kd + at, hard.item(), kd.item(), at.item()\n\ndef train_at_kd(student, teacher, loader, device, epochs=3):\n    teacher.eval()\n    for p in teacher.parameters(): p.requires_grad_(False)\n    optimizer = optim.SGD(student.parameters(), lr=0.01,\n                          momentum=0.9, weight_decay=1e-4)\n    for epoch in range(epochs):\n        student.train()\n        total = 0.0\n        for X, y in loader:\n            X, y = X.to(device), y.to(device)\n            with torch.no_grad():\n                t_logits, t_feats = teacher(X, return_feats=True)\n            s_logits, s_feats = student(X, return_feats=True)\n            loss, h, k, a = combined_at_kd_loss(s_logits, t_logits,\n                                                  s_feats, t_feats, y)\n            optimizer.zero_grad(); loss.backward(); optimizer.step()\n            total += loss.item()\n        print(f\u0027Epoch {epoch+1}: total={total/len(loader):.4f}  h={h:.3f}  kd={k:.3f}  at={a:.3f}\u0027)\n\nprint(\u0027AT+KD: student forward must return (logits, [feat_stage1, feat_stage2, feat_stage3]).\u0027)"},{"type":"heading","level":2,"content":"SemCKD and Cross-Layer Attention Transfer"},{"type":"text","content":"Semantic Calibration for Knowledge Distillation (SemCKD, Chen et al. 2021) extends AT to cross-layer attention: instead of matching each student layer to one teacher layer, it computes an attention matrix A ∈ ℝ^{N_s × N_t} that assigns each student layer to a weighted combination of teacher layers. The weights are learned during training, allowing the student to align with whichever teacher layer is most informative for each student layer. This avoids the hand-tuned layer pairing required by FitNets and AT."},{"type":"callout","variant":"tip","title":"When to Use AT vs FitNets vs CRD","content":"Use AT when you want a simple, low-overhead feature distillation with no extra parameters (no adapter, no memory bank). Use FitNets when the student is much shallower and needs guided intermediate representations to find a good optimization path. Use CRD when you can afford the memory bank and want the strongest single-method benchmark performance. For production, AT + logit KD combined is often the best effort-to-gain trade-off."},{"type":"heading","level":2,"content":"Practical Recommendations"},{"type":"list","ordered":false,"items":["Apply AT at all downsampling boundaries (after each ResNet stage) — 3 or 4 loss terms total.","β=1000 is robust across datasets; reduce to 100 if the AT loss dominates the logit KD term in early training.","Combine AT with logit KD (T=4, α=0.3): pure AT without logit KD consistently underperforms the combined loss.","Gradient-AT (Jacobian maps) gives higher cosine similarity but requires an extra backward pass per layer — use only at 1–2 key layers.","SemCKD is the strongest variant but adds learned cross-layer attention parameters; reserve for benchmark-critical use cases.","Spatial size mismatch: bilinear-interpolate the teacher\u0027s attention map to match the student\u0027s (H×W) before computing the loss.","Monitor cosine similarity between teacher and student attention maps during training as a diagnostic — stalled similarity indicates too-small β or bad layer pairing."]},{"type":"table","headers":["Method","What Is Matched","Spatial Info","Gradient Cost","Accuracy Gain","Layers Used"],"rows":[["Feature KD (FitNets)","Raw feature maps (L2 MSE)","Yes (H×W)","Low","+2.5–4.0%","One hint layer"],["AT (Zagoruyko 2017)","Sum-squared attention maps","Yes (H×W)","Low","+2.0–3.5%","Multiple stages"],["Gradient-AT (Jacobian)","Jacobian of output w.r.t. features","Yes (H×W)","High — extra backward per layer","+3.0–4.5%","1–2 key layers"],["SemCKD (Chen 2021)","Cross-layer attention matrix (N×N)","Cross-layer","Medium — learned attention weights","+3.5–5.0%","All layer pairs"],["GradCAM-AT","Class activation saliency maps","Yes (H×W)","High — class-specific backward pass","+2.5–4.0%","Multiple stages"]]},{"type":"divider"}]"
---
# Attention Transfer — Spatial Attention Map Distillation

Attention Transfer (Zagoruyko & Komodakis 2017) distills not what the teacher knows but where it looks. A well-trained teacher has learned to focus on discriminative regions — the animal's face rather than the background, the wheel arch rather than the car door. The student should look at those same regions. AT computes a spatial attention map from each intermediate feature tensor and penalizes the student for looking at different regions than the teacher.

## Attention Map Computation: Sum, Max, and L2

Given a feature tensor F ∈ ℝ^{C×H×W}, three attention map variants are commonly used. Sum-squared (default AT): A_sum = Σ_c F_k² — sum of squared activations over channels, producing a (H×W) heatmap. Max absolute: A_max = max_c |F_k| — maximum absolute activation over channels. L2 norm: A_l2 = ‖F_k‖_2 over channels. All maps are normalized by their Frobenius norm: Ā = A / ‖A‖_F. The sum-squared variant is the standard choice and performs best in practice.

```python
import torch
import torch.nn.functional as F

def compute_attention_maps(feature: torch.Tensor):
    """
    Compute three attention map variants from F in R^{B x C x H x W}.
    All maps normalized to unit L2 norm per sample.
    Returns: (A_sum, A_max, A_l2) each of shape (B, H*W).
    """
    B, C, H, W = feature.shape

    A_sum = feature.pow(2).sum(dim=1).view(B, -1)       # (B, H*W)
    A_max = feature.abs().max(dim=1).values.view(B, -1)  # (B, H*W)
    A_l2  = feature.norm(p=2, dim=1).view(B, -1)         # (B, H*W)

    normalize = lambda A: F.normalize(A, p=2, dim=1)
    return normalize(A_sum), normalize(A_max), normalize(A_l2)


torch.manual_seed(7)
B, C, H, W = 4, 128, 8, 8
feature = torch.randn(B, C, H, W)

A_sum, A_max, A_l2 = compute_attention_maps(feature)
print(f'Feature shape:   {feature.shape}')
print(f'Attention shapes: sum={A_sum.shape}  max={A_max.shape}  l2={A_l2.shape}')

# Cross-variant correlation (should be high — all capture similar spatial structure)
corr_sm = (A_sum * A_max).sum(1).mean().item()
corr_sl = (A_sum * A_l2).sum(1).mean().item()
print(f'Correlation sum-max: {corr_sm:.4f}   sum-l2: {corr_sl:.4f}')
print('Sum-of-squares is standard (Zagoruyko & Komodakis 2017).')
```

## AT Loss at Multiple Intermediate Layers

Applying AT at a single layer provides limited supervision. The full AT method applies the loss after each major stage (e.g., after each residual block group in ResNet). This means the student is guided to look in the right places at every level of abstraction — low-level texture regions in early stages, semantic object regions in later stages. The total AT loss is the sum across all paired stages, each weighted by the same β.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def at_map(feature: torch.Tensor) -> torch.Tensor:
    """Sum-of-squared channels attention map, L2-normalized. Shape: (B, H*W)."""
    B = feature.shape[0]
    A = feature.pow(2).sum(dim=1).view(B, -1)
    return F.normalize(A, p=2, dim=1)

class MultiStageATLoss(nn.Module):
    """AT loss summed over multiple paired feature map stages."""

    def __init__(self, beta: float = 1000.0):
        super().__init__()
        self.beta = beta

    def forward(self, student_feats: list, teacher_feats: list) -> torch.Tensor:
        assert len(student_feats) == len(teacher_feats)
        device = student_feats[0].device
        total = torch.zeros(1, device=device)
        for fs, ft in zip(student_feats, teacher_feats):
            A_s = at_map(fs)
            A_t = at_map(ft).detach()
            if A_s.shape != A_t.shape:  # resample if spatial sizes differ
                A_t = F.interpolate(A_t.unsqueeze(1),
                                    size=A_s.shape[-1], mode='linear').squeeze(1)
            total = total + (self.beta / 2.0) * (A_s - A_t).pow(2).mean()
        return total


# Demo: 3-stage ResNet-style feature maps (teacher wider than student)
B = 4
student_feats = [torch.randn(B,  64, 28, 28),
                 torch.randn(B, 128, 14, 14),
                 torch.randn(B, 256,  7,  7)]
teacher_feats = [torch.randn(B, 128, 28, 28),
                 torch.randn(B, 256, 14, 14),
                 torch.randn(B, 512,  7,  7)]

at_loss = MultiStageATLoss(beta=1000.0)
loss = at_loss(student_feats, teacher_feats)
print(f'Multi-stage AT loss (3 stages): {loss.item():.4f}')
```

## Gradient-Based Attention Maps

An alternative to activation-based maps is gradient-based attention: the Jacobian of the model's output with respect to an intermediate feature tensor. ∂y/∂F_k captures how sensitive the final prediction is to each spatial location in layer k — a more informative signal than raw activation magnitudes. GradCAM-style attention combines gradients and activations: A_GradCAM = ReLU(Σ_c (∂y/∂F_c) · F_c). The cost is one additional backward pass per layer; impractical for all layers but effective at a single carefully chosen layer.

## Visualizing Teacher vs Student Attention

Before and after AT training, comparing the teacher's and student's attention maps reveals whether the student has learned to look at the right image regions. High cosine similarity between the flattened, normalized maps indicates successful attention transfer. In practice, a student trained with AT shows much higher cosine similarity to the teacher's maps than a student trained with logit KD alone, which explains the accuracy improvement — the student literally focuses on the correct discriminative regions.

```python
import torch
import torch.nn.functional as F
import numpy as np

def attention_heatmap(feature: torch.Tensor) -> np.ndarray:
    """Convert a single-sample feature (C, H, W) to a normalized (H, W) heatmap."""
    A = feature.pow(2).sum(dim=0).detach().cpu().numpy()  # (H, W)
    return (A - A.min()) / (A.max() - A.min() + 1e-6)

def compare_attention_maps(teacher_feat: torch.Tensor, student_feat: torch.Tensor):
    """Print statistics comparing teacher and student spatial attention."""
    A_t = attention_heatmap(teacher_feat)
    A_s = attention_heatmap(student_feat)

    t_flat = A_t.flatten()
    s_flat = A_s.flatten()
    cos_sim = np.dot(t_flat, s_flat) / (
        np.linalg.norm(t_flat) * np.linalg.norm(s_flat) + 1e-6)

    print(f'Teacher attn — mean: {A_t.mean():.4f}  std: {A_t.std():.4f}  max: {A_t.max():.4f}')
    print(f'Student attn — mean: {A_s.mean():.4f}  std: {A_s.std():.4f}  max: {A_s.max():.4f}')
    print(f'Cosine similarity (teacher vs student): {cos_sim:.4f}')
    print('After AT training, cosine similarity should approach 1.0.')


torch.manual_seed(3)
C, H, W = 64, 14, 14
teacher_feat = torch.randn(C, H, W).abs()  # post-ReLU, non-negative
student_feat = torch.randn(C, H, W).abs()
compare_attention_maps(teacher_feat, student_feat)
```

## AT + Logit KD Combined Training

AT alone without logit KD leaves accuracy on the table. The best results come from combining both: the logit KD term transfers class-level dark knowledge while the AT term aligns spatial attention at every stage. The combined loss is L = α·CE(hard) + (1-α)·T²·KL(soft) + L_AT. Typical weights: α=0.3, β=1000. The AT term is usually unweighted relative to the KD term; its natural scale matches the KD loss without explicit tuning.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import torch.optim as optim

def at_map(feature):
    B = feature.shape[0]
    return F.normalize(feature.pow(2).sum(1).view(B, -1), p=2, dim=1)

def combined_at_kd_loss(s_logits, t_logits, s_feats, t_feats, labels,
                         T=4.0, alpha=0.3, beta=1000.0):
    """CE + logit KD + multi-stage AT."""
    hard = F.cross_entropy(s_logits, labels)
    kd   = F.kl_div(F.log_softmax(s_logits / T, dim=-1),
                    F.softmax(t_logits / T, dim=-1).detach(),
                    reduction='batchmean') * T ** 2
    at   = sum((beta / 2.0) * (at_map(fs) - at_map(ft).detach()).pow(2).mean()
               for fs, ft in zip(s_feats, t_feats))
    return alpha * hard + (1 - alpha) * kd + at, hard.item(), kd.item(), at.item()

def train_at_kd(student, teacher, loader, device, epochs=3):
    teacher.eval()
    for p in teacher.parameters(): p.requires_grad_(False)
    optimizer = optim.SGD(student.parameters(), lr=0.01,
                          momentum=0.9, weight_decay=1e-4)
    for epoch in range(epochs):
        student.train()
        total = 0.0
        for X, y in loader:
            X, y = X.to(device), y.to(device)
            with torch.no_grad():
                t_logits, t_feats = teacher(X, return_feats=True)
            s_logits, s_feats = student(X, return_feats=True)
            loss, h, k, a = combined_at_kd_loss(s_logits, t_logits,
                                                  s_feats, t_feats, y)
            optimizer.zero_grad(); loss.backward(); optimizer.step()
            total += loss.item()
        print(f'Epoch {epoch+1}: total={total/len(loader):.4f}  h={h:.3f}  kd={k:.3f}  at={a:.3f}')

print('AT+KD: student forward must return (logits, [feat_stage1, feat_stage2, feat_stage3]).')
```

## SemCKD and Cross-Layer Attention Transfer

Semantic Calibration for Knowledge Distillation (SemCKD, Chen et al. 2021) extends AT to cross-layer attention: instead of matching each student layer to one teacher layer, it computes an attention matrix A ∈ ℝ^{N_s × N_t} that assigns each student layer to a weighted combination of teacher layers. The weights are learned during training, allowing the student to align with whichever teacher layer is most informative for each student layer. This avoids the hand-tuned layer pairing required by FitNets and AT.

> **When to Use AT vs FitNets vs CRD**: Use AT when you want a simple, low-overhead feature distillation with no extra parameters (no adapter, no memory bank). Use FitNets when the student is much shallower and needs guided intermediate representations to find a good optimization path. Use CRD when you can afford the memory bank and want the strongest single-method benchmark performance. For production, AT + logit KD combined is often the best effort-to-gain trade-off.

## Practical Recommendations

- Apply AT at all downsampling boundaries (after each ResNet stage) — 3 or 4 loss terms total.
- β=1000 is robust across datasets; reduce to 100 if the AT loss dominates the logit KD term in early training.
- Combine AT with logit KD (T=4, α=0.3): pure AT without logit KD consistently underperforms the combined loss.
- Gradient-AT (Jacobian maps) gives higher cosine similarity but requires an extra backward pass per layer — use only at 1–2 key layers.
- SemCKD is the strongest variant but adds learned cross-layer attention parameters; reserve for benchmark-critical use cases.
- Spatial size mismatch: bilinear-interpolate the teacher's attention map to match the student's (H×W) before computing the loss.
- Monitor cosine similarity between teacher and student attention maps during training as a diagnostic — stalled similarity indicates too-small β or bad layer pairing.

| Method | What Is Matched | Spatial Info | Gradient Cost | Accuracy Gain | Layers Used |
| --- | --- | --- | --- | --- | --- |
| Feature KD (FitNets) | Raw feature maps (L2 MSE) | Yes (H×W) | Low | +2.5–4.0% | One hint layer |
| AT (Zagoruyko 2017) | Sum-squared attention maps | Yes (H×W) | Low | +2.0–3.5% | Multiple stages |
| Gradient-AT (Jacobian) | Jacobian of output w.r.t. features | Yes (H×W) | High — extra backward per layer | +3.0–4.5% | 1–2 key layers |
| SemCKD (Chen 2021) | Cross-layer attention matrix (N×N) | Cross-layer | Medium — learned attention weights | +3.5–5.0% | All layer pairs |
| GradCAM-AT | Class activation saliency maps | Yes (H×W) | High — class-specific backward pass | +2.5–4.0% | Multiple stages |

---

