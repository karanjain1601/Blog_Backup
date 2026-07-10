---
title: "Feature Map Distillation — FitNets and Intermediate Representations"
slug: "feature-map-distillation"
description: "Go beyond output logits by aligning intermediate feature maps between teacher and student. Covers FitNets hint training, two-stage schedules, attention transfer, layer-to-layer mapping, PKT, CRD, and a comparison of feature distillation methods."
tags: ["deep-learning", "model-compression", "knowledge-distillation"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Output-only knowledge distillation transfers only the teacher\u0027s final predictions. This misses the rich intermediate representations built up across the teacher\u0027s layers — representations encoding edges, textures, object parts, and semantic structure. Feature map distillation methods transfer these internal representations directly, giving the student a richer training signal and better initialization for learning the task."},{"type":"heading","level":2,"content":"FitNets and Hint Layer Training"},{"type":"text","content":"FitNets (Romero et al. 2015) extend distillation to intermediate layers. A \u0027hint layer\u0027 in the teacher and a \u0027guided layer\u0027 in the student are chosen at matching depths. The student is trained to predict the teacher\u0027s hint layer output: L_hint = ‖W_h(F_student) - F_teacher‖², where W_h is a 1×1 convolutional adapter that projects the student\u0027s feature map to the teacher\u0027s channel dimension. This forces the student to build the same intermediate representations as the teacher, not just match final predictions."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass HintLoss(nn.Module):\n    \"\"\"FitNets hint loss: align student feature map to teacher via 1x1 conv adapter.\"\"\"\n\n    def __init__(self, student_channels: int, teacher_channels: int):\n        super().__init__()\n        # Adapter W_h: maps student dim -\u003e teacher dim\n        self.adapter = nn.Conv2d(student_channels, teacher_channels,\n                                 kernel_size=1, bias=False)\n\n    def forward(self, f_student: torch.Tensor, f_teacher: torch.Tensor) -\u003e torch.Tensor:\n        \"\"\"\n        f_student: (B, C_S, H, W)  student intermediate feature map\n        f_teacher: (B, C_T, H, W)  teacher intermediate feature map (detached)\n        Returns: ||W_h(F_s) - F_t||^2 / N\n        \"\"\"\n        f_adapted = self.adapter(f_student)           # (B, C_T, H, W)\n        return F.mse_loss(f_adapted, f_teacher.detach())\n\n\ntorch.manual_seed(0)\nB, H, W = 4, 14, 14\nC_teacher, C_student = 256, 128\n\nf_teacher = torch.randn(B, C_teacher, H, W)\nf_student  = torch.randn(B, C_student,  H, W)\n\nhint = HintLoss(C_student, C_teacher)\nloss = hint(f_student, f_teacher)\nprint(f\u0027Hint loss: {loss.item():.4f}\u0027)\nprint(f\u0027Adapter: {C_student} -\u003e {C_teacher} channels, params: {sum(p.numel() for p in hint.parameters())}\u0027)"},{"type":"heading","level":2,"content":"Two-Stage Training: Hint Then KD"},{"type":"text","content":"FitNets use two training stages. Stage 1 (hint training): optimize only the hint loss L_hint to align the student\u0027s intermediate feature map with the teacher\u0027s hint layer. This gives the student a better starting point than random initialization. Stage 2 (KD training): discard the adapter and train the full student with the standard logit-level distillation loss using the teacher\u0027s output probabilities. The two-stage schedule consistently outperforms single-stage logit KD, especially for deep students trained on small datasets."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport torch.optim as optim\n\ndef stage1_hint_training(student, teacher, hint_loss_fn, loader, device, epochs=2, lr=1e-3):\n    \"\"\"Stage 1: train student to match teacher intermediate feature maps.\"\"\"\n    params = list(student.parameters()) + list(hint_loss_fn.parameters())\n    optimizer = optim.Adam(params, lr=lr)\n    for epoch in range(epochs):\n        total = 0.0\n        for X, _ in loader:\n            X = X.to(device)\n            with torch.no_grad():\n                f_teacher = teacher.get_hint_features(X)\n            f_student = student.get_guided_features(X)\n            loss = hint_loss_fn(f_student, f_teacher)\n            optimizer.zero_grad()\n            loss.backward()\n            optimizer.step()\n            total += loss.item()\n        print(f\u0027  Hint epoch {epoch+1}: hint_loss={total/len(loader):.4f}\u0027)\n\ndef stage2_kd_training(student, teacher, loader, device,\n                        temperature=4.0, alpha=0.5, epochs=5, lr=5e-4):\n    \"\"\"Stage 2: full KD with teacher logits (hint adapter is discarded).\"\"\"\n    optimizer = optim.Adam(student.parameters(), lr=lr)\n    T = temperature\n    for epoch in range(epochs):\n        total = 0.0\n        for X, y in loader:\n            X, y = X.to(device), y.to(device)\n            with torch.no_grad():\n                t_logits = teacher(X)\n            s_logits = student(X)\n            hard = F.cross_entropy(s_logits, y)\n            soft = F.kl_div(F.log_softmax(s_logits / T, dim=-1),\n                            F.softmax(t_logits / T, dim=-1),\n                            reduction=\u0027batchmean\u0027) * T ** 2\n            loss = alpha * hard + (1 - alpha) * soft\n            optimizer.zero_grad(); loss.backward(); optimizer.step()\n            total += loss.item()\n        print(f\u0027  KD epoch {epoch+1}: loss={total/len(loader):.4f}\u0027)\n\nprint(\u0027Two-stage FitNets: stage1=hint alignment, stage2=full logit KD.\u0027)"},{"type":"heading","level":2,"content":"Attention Transfer (AT) Loss"},{"type":"text","content":"Attention Transfer (Zagoruyko \u0026 Komodakis 2017) distills spatial attention maps rather than raw feature values. The attention map from feature tensor F ∈ ℝ^{C×H×W} is computed as A_sum = Σ_c F_k² — summing squared activations over the channel dimension, yielding a (H×W) heatmap of \u0027where\u0027 the network is looking. After normalizing by the Frobenius norm, the AT loss minimizes β/2 · ‖Ā_student - Ā_teacher‖². This is applied at multiple intermediate stages simultaneously."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef attention_map(feature: torch.Tensor, mode: str = \u0027sum\u0027) -\u003e torch.Tensor:\n    \"\"\"\n    Compute spatial attention map from F in R^{B x C x H x W}.\n    mode=\u0027sum\u0027: sum of squared activations over channels -\u003e (B, H*W)\n    mode=\u0027max\u0027: max absolute activation over channels -\u003e (B, H*W)\n    Returns L2-normalized map.\n    \"\"\"\n    B = feature.shape[0]\n    if mode == \u0027sum\u0027:\n        A = feature.pow(2).sum(dim=1).view(B, -1)       # (B, H*W)\n    elif mode == \u0027max\u0027:\n        A = feature.abs().max(dim=1).values.view(B, -1)  # (B, H*W)\n    else:\n        raise ValueError(f\u0027Unknown mode: {mode}\u0027)\n    return F.normalize(A, p=2, dim=1)\n\ndef at_loss(f_student: torch.Tensor, f_teacher: torch.Tensor, beta: float = 1000.0) -\u003e torch.Tensor:\n    \"\"\"AT loss: beta/2 * ||A_student - A_teacher||^2\"\"\"\n    A_s = attention_map(f_student)\n    A_t = attention_map(f_teacher).detach()\n    return (beta / 2.0) * (A_s - A_t).pow(2).mean()\n\n\nB, C, H, W = 4, 64, 14, 14\nf_s = torch.randn(B, C, H, W)\nf_t = torch.randn(B, C, H, W)\nloss = at_loss(f_s, f_t, beta=1000.0)\nprint(f\u0027AT loss (sum mode): {loss.item():.4f}\u0027)\nA = attention_map(f_s)\nprint(f\u0027Attention map shape: {A.shape}  (norm should be ~1): {A.norm(dim=1).mean().item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Layer-to-Layer Mapping"},{"type":"text","content":"Choosing which student layer to align with which teacher layer requires care. A mismatch in spatial resolution makes direct comparison impossible without upsampling. The standard strategy is to match layers by their spatial resolution (H×W): after each downsampling stage in the teacher, find the corresponding student layer with the same spatial output size. For ResNet-style networks this is straightforward — each stage cuts spatial resolution by 2×. For architectures with different depths, a regressor network that maps between mismatched resolutions is needed."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef map_layers_by_spatial_size(teacher: nn.Module, student: nn.Module,\n                                input_shape=(1, 3, 32, 32)):\n    \"\"\"\n    Register forward hooks, run a dummy input, then match student/teacher\n    Conv2d layers that share the same spatial output resolution (H x W).\n    \"\"\"\n    teacher_shapes, student_shapes = {}, {}\n\n    def make_hook(store, name):\n        def hook(_, __, out):\n            if isinstance(out, torch.Tensor):\n                store[name] = tuple(out.shape[2:])  # (H, W)\n        return hook\n\n    t_hooks = [m.register_forward_hook(make_hook(teacher_shapes, f\u0027T.{n}\u0027))\n               for n, m in teacher.named_modules() if isinstance(m, nn.Conv2d)]\n    s_hooks = [m.register_forward_hook(make_hook(student_shapes, f\u0027S.{n}\u0027))\n               for n, m in student.named_modules() if isinstance(m, nn.Conv2d)]\n\n    with torch.no_grad():\n        teacher(torch.randn(input_shape))\n        student(torch.randn(input_shape))\n    for h in t_hooks + s_hooks: h.remove()\n\n    print(f\u0027{\"Teacher layer\":\u003c30} \u003c-\u003e {\"Student layer\":\u003c30}  {\"HxW\"}\u0027)\n    print(\u0027-\u0027 * 75)\n    matched = []\n    for t_name, t_hw in teacher_shapes.items():\n        for s_name, s_hw in student_shapes.items():\n            if t_hw == s_hw and (t_name, s_name) not in matched:\n                print(f\u0027{t_name:\u003c30}     {s_name:\u003c30}  {t_hw}\u0027)\n                matched.append((t_name, s_name))\n                break\n    return matched\n\nteacher = nn.Sequential(nn.Conv2d(3, 64, 3, padding=1), nn.Conv2d(64, 128, 3, stride=2, padding=1))\nstudent = nn.Sequential(nn.Conv2d(3, 32, 3, padding=1), nn.Conv2d(32,  64, 3, stride=2, padding=1))\nmap_layers_by_spatial_size(teacher, student)"},{"type":"heading","level":2,"content":"Beyond FitNets: PKT, CRD, and NST"},{"type":"text","content":"Several methods extend the feature distillation idea. Probabilistic Knowledge Transfer (PKT, Passalis 2018) matches the distribution of student and teacher features by minimizing a kernel-based distance between their feature similarity matrices — an O(N²) operation over a batch. Contrastive Representation Distillation (CRD, Tian 2020) uses a contrastive objective: student features should be similar to the teacher\u0027s features for the same sample and dissimilar to features from other samples in a memory bank. Neuron Selectivity Transfer (NST) matches higher-order statistics of the feature distributions."},{"type":"callout","variant":"tip","title":"Choosing Between Logit KD and Feature Distillation","content":"Logit KD is simpler and often sufficient when teacher and student have similar depths. Use feature distillation (FitNets or AT) when the student is much shallower — the intermediate supervision guides the student through layers that would otherwise receive no direct gradient signal from the task. CRD is the strongest single method by benchmark but requires a memory bank and batch size tuning; AT is the best simplicity-vs-gain trade-off."},{"type":"heading","level":2,"content":"Practical Recommendations"},{"type":"text","content":"For FitNets, select the hint layer at roughly the midpoint of the teacher network, and the guided layer at the midpoint of the student. Use a 1×1 conv adapter if channel counts differ; bilinear interpolation if spatial sizes differ. Run Stage 1 for 20–30% of the total training budget, then Stage 2 for the remainder. Reduce the learning rate by 10× for Stage 2 relative to Stage 1 to avoid disrupting the hint-based initialization."},{"type":"list","ordered":false,"items":["Hint layer: teacher midpoint (e.g., layer 8 of 16); guided layer: student midpoint (e.g., layer 4 of 8).","Adapter W_h: 1×1 conv — adds only C_S × C_T parameters, negligible cost.","Stage 1 budget: 20–30% of total epochs; Stage 2: remaining 70–80% with logit KD.","AT beta hyperparameter: β=1000 is the default from the paper; scale down if AT loss dominates.","CRD memory bank size: 4096–16384 negatives; larger banks give better contrastive signal.","Layer mismatch: if teacher and student have different depths, apply AT only at the last 2–3 stages where spatial sizes match."]},{"type":"heading","level":2,"content":"Feature Distillation Method Comparison"},{"type":"table","headers":["Method","Matched Quantity","Adapter Needed","Accuracy Gain (CIFAR-100)","Computation Overhead"],"rows":[["Logit KD (Hinton)","Output probabilities","None","+1.5–2.5%","Low — one teacher forward pass"],["FitNets","Intermediate feature maps (L2)","1×1 conv (W_h)","+2.5–4.0%","Medium — two training stages"],["AT (Zagoruyko)","Spatial attention maps","None","+2.0–3.5%","Low — attention map computation only"],["PKT","Kernel-based feature similarity","Projection head","+2.0–3.0%","Medium — O(N²) kernel matrix"],["CRD (Tian 2020)","Contrastive pair similarity","Projection MLP","+3.5–5.0%","High — memory bank required"]]},{"type":"divider"}]"
---
# Feature Map Distillation — FitNets and Intermediate Representations

Output-only knowledge distillation transfers only the teacher's final predictions. This misses the rich intermediate representations built up across the teacher's layers — representations encoding edges, textures, object parts, and semantic structure. Feature map distillation methods transfer these internal representations directly, giving the student a richer training signal and better initialization for learning the task.

## FitNets and Hint Layer Training

FitNets (Romero et al. 2015) extend distillation to intermediate layers. A 'hint layer' in the teacher and a 'guided layer' in the student are chosen at matching depths. The student is trained to predict the teacher's hint layer output: L_hint = ‖W_h(F_student) - F_teacher‖², where W_h is a 1×1 convolutional adapter that projects the student's feature map to the teacher's channel dimension. This forces the student to build the same intermediate representations as the teacher, not just match final predictions.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class HintLoss(nn.Module):
    """FitNets hint loss: align student feature map to teacher via 1x1 conv adapter."""

    def __init__(self, student_channels: int, teacher_channels: int):
        super().__init__()
        # Adapter W_h: maps student dim -> teacher dim
        self.adapter = nn.Conv2d(student_channels, teacher_channels,
                                 kernel_size=1, bias=False)

    def forward(self, f_student: torch.Tensor, f_teacher: torch.Tensor) -> torch.Tensor:
        """
        f_student: (B, C_S, H, W)  student intermediate feature map
        f_teacher: (B, C_T, H, W)  teacher intermediate feature map (detached)
        Returns: ||W_h(F_s) - F_t||^2 / N
        """
        f_adapted = self.adapter(f_student)           # (B, C_T, H, W)
        return F.mse_loss(f_adapted, f_teacher.detach())


torch.manual_seed(0)
B, H, W = 4, 14, 14
C_teacher, C_student = 256, 128

f_teacher = torch.randn(B, C_teacher, H, W)
f_student  = torch.randn(B, C_student,  H, W)

hint = HintLoss(C_student, C_teacher)
loss = hint(f_student, f_teacher)
print(f'Hint loss: {loss.item():.4f}')
print(f'Adapter: {C_student} -> {C_teacher} channels, params: {sum(p.numel() for p in hint.parameters())}')
```

## Two-Stage Training: Hint Then KD

FitNets use two training stages. Stage 1 (hint training): optimize only the hint loss L_hint to align the student's intermediate feature map with the teacher's hint layer. This gives the student a better starting point than random initialization. Stage 2 (KD training): discard the adapter and train the full student with the standard logit-level distillation loss using the teacher's output probabilities. The two-stage schedule consistently outperforms single-stage logit KD, especially for deep students trained on small datasets.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import torch.optim as optim

def stage1_hint_training(student, teacher, hint_loss_fn, loader, device, epochs=2, lr=1e-3):
    """Stage 1: train student to match teacher intermediate feature maps."""
    params = list(student.parameters()) + list(hint_loss_fn.parameters())
    optimizer = optim.Adam(params, lr=lr)
    for epoch in range(epochs):
        total = 0.0
        for X, _ in loader:
            X = X.to(device)
            with torch.no_grad():
                f_teacher = teacher.get_hint_features(X)
            f_student = student.get_guided_features(X)
            loss = hint_loss_fn(f_student, f_teacher)
            optimizer.zero_grad()
            loss.backward()
            optimizer.step()
            total += loss.item()
        print(f'  Hint epoch {epoch+1}: hint_loss={total/len(loader):.4f}')

def stage2_kd_training(student, teacher, loader, device,
                        temperature=4.0, alpha=0.5, epochs=5, lr=5e-4):
    """Stage 2: full KD with teacher logits (hint adapter is discarded)."""
    optimizer = optim.Adam(student.parameters(), lr=lr)
    T = temperature
    for epoch in range(epochs):
        total = 0.0
        for X, y in loader:
            X, y = X.to(device), y.to(device)
            with torch.no_grad():
                t_logits = teacher(X)
            s_logits = student(X)
            hard = F.cross_entropy(s_logits, y)
            soft = F.kl_div(F.log_softmax(s_logits / T, dim=-1),
                            F.softmax(t_logits / T, dim=-1),
                            reduction='batchmean') * T ** 2
            loss = alpha * hard + (1 - alpha) * soft
            optimizer.zero_grad(); loss.backward(); optimizer.step()
            total += loss.item()
        print(f'  KD epoch {epoch+1}: loss={total/len(loader):.4f}')

print('Two-stage FitNets: stage1=hint alignment, stage2=full logit KD.')
```

## Attention Transfer (AT) Loss

Attention Transfer (Zagoruyko & Komodakis 2017) distills spatial attention maps rather than raw feature values. The attention map from feature tensor F ∈ ℝ^{C×H×W} is computed as A_sum = Σ_c F_k² — summing squared activations over the channel dimension, yielding a (H×W) heatmap of 'where' the network is looking. After normalizing by the Frobenius norm, the AT loss minimizes β/2 · ‖Ā_student - Ā_teacher‖². This is applied at multiple intermediate stages simultaneously.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def attention_map(feature: torch.Tensor, mode: str = 'sum') -> torch.Tensor:
    """
    Compute spatial attention map from F in R^{B x C x H x W}.
    mode='sum': sum of squared activations over channels -> (B, H*W)
    mode='max': max absolute activation over channels -> (B, H*W)
    Returns L2-normalized map.
    """
    B = feature.shape[0]
    if mode == 'sum':
        A = feature.pow(2).sum(dim=1).view(B, -1)       # (B, H*W)
    elif mode == 'max':
        A = feature.abs().max(dim=1).values.view(B, -1)  # (B, H*W)
    else:
        raise ValueError(f'Unknown mode: {mode}')
    return F.normalize(A, p=2, dim=1)

def at_loss(f_student: torch.Tensor, f_teacher: torch.Tensor, beta: float = 1000.0) -> torch.Tensor:
    """AT loss: beta/2 * ||A_student - A_teacher||^2"""
    A_s = attention_map(f_student)
    A_t = attention_map(f_teacher).detach()
    return (beta / 2.0) * (A_s - A_t).pow(2).mean()


B, C, H, W = 4, 64, 14, 14
f_s = torch.randn(B, C, H, W)
f_t = torch.randn(B, C, H, W)
loss = at_loss(f_s, f_t, beta=1000.0)
print(f'AT loss (sum mode): {loss.item():.4f}')
A = attention_map(f_s)
print(f'Attention map shape: {A.shape}  (norm should be ~1): {A.norm(dim=1).mean().item():.4f}')
```

## Layer-to-Layer Mapping

Choosing which student layer to align with which teacher layer requires care. A mismatch in spatial resolution makes direct comparison impossible without upsampling. The standard strategy is to match layers by their spatial resolution (H×W): after each downsampling stage in the teacher, find the corresponding student layer with the same spatial output size. For ResNet-style networks this is straightforward — each stage cuts spatial resolution by 2×. For architectures with different depths, a regressor network that maps between mismatched resolutions is needed.

```python
import torch
import torch.nn as nn

def map_layers_by_spatial_size(teacher: nn.Module, student: nn.Module,
                                input_shape=(1, 3, 32, 32)):
    """
    Register forward hooks, run a dummy input, then match student/teacher
    Conv2d layers that share the same spatial output resolution (H x W).
    """
    teacher_shapes, student_shapes = {}, {}

    def make_hook(store, name):
        def hook(_, __, out):
            if isinstance(out, torch.Tensor):
                store[name] = tuple(out.shape[2:])  # (H, W)
        return hook

    t_hooks = [m.register_forward_hook(make_hook(teacher_shapes, f'T.{n}'))
               for n, m in teacher.named_modules() if isinstance(m, nn.Conv2d)]
    s_hooks = [m.register_forward_hook(make_hook(student_shapes, f'S.{n}'))
               for n, m in student.named_modules() if isinstance(m, nn.Conv2d)]

    with torch.no_grad():
        teacher(torch.randn(input_shape))
        student(torch.randn(input_shape))
    for h in t_hooks + s_hooks: h.remove()

    print(f'{"Teacher layer":<30} <-> {"Student layer":<30}  {"HxW"}')
    print('-' * 75)
    matched = []
    for t_name, t_hw in teacher_shapes.items():
        for s_name, s_hw in student_shapes.items():
            if t_hw == s_hw and (t_name, s_name) not in matched:
                print(f'{t_name:<30}     {s_name:<30}  {t_hw}')
                matched.append((t_name, s_name))
                break
    return matched

teacher = nn.Sequential(nn.Conv2d(3, 64, 3, padding=1), nn.Conv2d(64, 128, 3, stride=2, padding=1))
student = nn.Sequential(nn.Conv2d(3, 32, 3, padding=1), nn.Conv2d(32,  64, 3, stride=2, padding=1))
map_layers_by_spatial_size(teacher, student)
```

## Beyond FitNets: PKT, CRD, and NST

Several methods extend the feature distillation idea. Probabilistic Knowledge Transfer (PKT, Passalis 2018) matches the distribution of student and teacher features by minimizing a kernel-based distance between their feature similarity matrices — an O(N²) operation over a batch. Contrastive Representation Distillation (CRD, Tian 2020) uses a contrastive objective: student features should be similar to the teacher's features for the same sample and dissimilar to features from other samples in a memory bank. Neuron Selectivity Transfer (NST) matches higher-order statistics of the feature distributions.

> **Choosing Between Logit KD and Feature Distillation**: Logit KD is simpler and often sufficient when teacher and student have similar depths. Use feature distillation (FitNets or AT) when the student is much shallower — the intermediate supervision guides the student through layers that would otherwise receive no direct gradient signal from the task. CRD is the strongest single method by benchmark but requires a memory bank and batch size tuning; AT is the best simplicity-vs-gain trade-off.

## Practical Recommendations

For FitNets, select the hint layer at roughly the midpoint of the teacher network, and the guided layer at the midpoint of the student. Use a 1×1 conv adapter if channel counts differ; bilinear interpolation if spatial sizes differ. Run Stage 1 for 20–30% of the total training budget, then Stage 2 for the remainder. Reduce the learning rate by 10× for Stage 2 relative to Stage 1 to avoid disrupting the hint-based initialization.

- Hint layer: teacher midpoint (e.g., layer 8 of 16); guided layer: student midpoint (e.g., layer 4 of 8).
- Adapter W_h: 1×1 conv — adds only C_S × C_T parameters, negligible cost.
- Stage 1 budget: 20–30% of total epochs; Stage 2: remaining 70–80% with logit KD.
- AT beta hyperparameter: β=1000 is the default from the paper; scale down if AT loss dominates.
- CRD memory bank size: 4096–16384 negatives; larger banks give better contrastive signal.
- Layer mismatch: if teacher and student have different depths, apply AT only at the last 2–3 stages where spatial sizes match.

## Feature Distillation Method Comparison

| Method | Matched Quantity | Adapter Needed | Accuracy Gain (CIFAR-100) | Computation Overhead |
| --- | --- | --- | --- | --- |
| Logit KD (Hinton) | Output probabilities | None | +1.5–2.5% | Low — one teacher forward pass |
| FitNets | Intermediate feature maps (L2) | 1×1 conv (W_h) | +2.5–4.0% | Medium — two training stages |
| AT (Zagoruyko) | Spatial attention maps | None | +2.0–3.5% | Low — attention map computation only |
| PKT | Kernel-based feature similarity | Projection head | +2.0–3.0% | Medium — O(N²) kernel matrix |
| CRD (Tian 2020) | Contrastive pair similarity | Projection MLP | +3.5–5.0% | High — memory bank required |

---

