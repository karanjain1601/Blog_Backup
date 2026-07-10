---
title: "DINO — Self-Distillation Without Labels"
slug: "dino-self-distillation"
description: "How DINO (Caron et al. 2021) uses a student-teacher self-distillation framework with EMA weight updates, multi-crop training, centering and sharpening for collapse prevention, and emergent attention-based segmentation."
tags: ["deep-learning", "self-supervised-learning", "masked-learning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"DINO (Self-DIstillation with NO labels) by Caron et al. (2021) showed that self-supervised ViT features trained with knowledge distillation between a student and an EMA teacher develop emergent properties absent in supervised models — most strikingly, attention maps that align precisely with semantic object boundaries without ever seeing a segmentation label."},{"type":"heading","level":2,"content":"Self-Distillation Concept"},{"type":"text","content":"DINO uses a student-teacher framework where both networks share the same ViT architecture. The teacher is an exponential moving average (EMA) of the student\u0027s weights — it never receives gradients directly. The student is trained to predict the teacher\u0027s output distribution for different augmented views of the same image. Because the teacher is a smoothed version of the student, this is called self-distillation."},{"type":"heading","level":2,"content":"Teacher EMA Update"},{"type":"text","content":"The teacher\u0027s parameters are updated via EMA with a momentum coefficient m that is annealed from 0.996 toward 1.0 during training using a cosine schedule. Higher momentum (m → 1.0) means the teacher changes more slowly — providing a stable training target. The student is updated via standard gradient descent; the teacher receives no gradient signal."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\nimport copy\n\nclass DINOTeacherUpdater:\n    def __init__(self, student, teacher, base_momentum=0.996):\n        self.student       = student\n        self.teacher       = teacher\n        self.base_momentum = base_momentum\n        # Initialize teacher from student weights; disable gradients\n        self.teacher.load_state_dict(student.state_dict())\n        for p in self.teacher.parameters():\n            p.requires_grad_(False)\n\n    def update(self, epoch, max_epochs):\n        # Momentum increases from base_momentum to 1.0 via cosine schedule\n        m = 1.0 - (1.0 - self.base_momentum) * (\n            np.cos(np.pi * epoch / max_epochs) + 1.0\n        ) / 2.0\n\n        with torch.no_grad():\n            for s_p, t_p in zip(\n                self.student.parameters(), self.teacher.parameters()\n            ):\n                t_p.data.mul_(m).add_((1.0 - m) * s_p.data)\n\n    @torch.no_grad()\n    def hard_copy(self):\n        # Copy student weights directly to teacher (used at initialization)\n        for s_p, t_p in zip(\n            self.student.parameters(), self.teacher.parameters()\n        ):\n            t_p.data.copy_(s_p.data)\n\n# Example: update teacher after each optimizer step\n# updater = DINOTeacherUpdater(student, teacher)\n# for epoch in range(max_epochs):\n#     ... train student ...\n#     updater.update(epoch, max_epochs)"},{"type":"heading","level":2,"content":"Centering and Sharpening"},{"type":"text","content":"Without any collapse prevention, self-distillation quickly collapses to a trivial solution where both student and teacher output a constant distribution. DINO uses two complementary mechanisms: centering (subtract a running mean from teacher logits to prevent one dimension from dominating) and sharpening (low temperature on the teacher to produce peaked distributions that carry a meaningful training signal)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass DINOHead(nn.Module):\n    def __init__(self, in_dim, out_dim=65536, center_momentum=0.9):\n        super().__init__()\n        self.mlp = nn.Sequential(\n            nn.Linear(in_dim, 2048), nn.GELU(),\n            nn.Linear(2048, 2048), nn.GELU(),\n            nn.Linear(2048, out_dim, bias=False)\n        )\n        self.register_buffer(\u0027center\u0027, torch.zeros(1, out_dim))\n        self.center_momentum = center_momentum\n\n    @torch.no_grad()\n    def update_center(self, teacher_output):\n        # EMA update: subtract running mean to prevent mode collapse\n        batch_center = teacher_output.mean(dim=0, keepdim=True)\n        self.center = (\n            self.center * self.center_momentum\n            + batch_center * (1 - self.center_momentum)\n        )\n\n    def teacher_softmax(self, x, temp=0.04):\n        # Subtract center, apply low temperature -\u003e sharp peaked distribution\n        return F.softmax((x - self.center) / temp, dim=-1)\n\n    def student_log_softmax(self, x, temp=0.1):\n        # Higher temperature for student -\u003e softer distribution\n        return F.log_softmax(x / temp, dim=-1)\n\n    def dino_loss(self, student_out, teacher_out):\n        # Cross-entropy H(teacher_sharp, student): student predicts teacher\n        t_probs  = self.teacher_softmax(teacher_out)\n        s_logp   = self.student_log_softmax(student_out)\n        return -(t_probs * s_logp).sum(dim=-1).mean()"},{"type":"callout","variant":"warning","title":"Collapse Prevention is Critical","content":"Without centering + sharpening, DINO collapses within the first few thousand iterations: the teacher outputs a uniform distribution (all images map to the same representation). Centering prevents any single dimension from dominating. Sharpening (low teacher temperature τ_t = 0.04) ensures the teacher outputs peaked distributions, giving the student a meaningful target to match. Both are required — centering alone still allows collapse to a uniform distribution."},{"type":"heading","level":2,"content":"Multi-Crop Training Strategy"},{"type":"text","content":"DINO uses a multi-crop augmentation strategy: generate 2 global crops (\u003e50% of image area) and 6–8 local crops (\u003c50% area). The teacher sees only the 2 global crops; the student sees all crops. The loss is computed as the cross-entropy from each student output to each teacher output (local→global matching). This teaches the student to predict global context from local views, forcing semantic feature learning."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torchvision.transforms as T\n\nclass MultiCropWrapper(nn.Module):\n    def __init__(self, backbone, head):\n        super().__init__()\n        self.backbone = backbone\n        self.head     = head\n\n    def forward(self, crops):\n        # Batch all crops together for a single efficient forward pass\n        all_crops = torch.cat(crops, dim=0)           # [sum(B), C, H, W]\n        features  = self.backbone(all_crops)          # [sum(B), D]\n        output    = self.head.mlp(features)           # [sum(B), out_dim]\n        # Split back into per-crop chunks\n        return output.split([c.shape[0] for c in crops], dim=0)\n\ndef dino_train_step(student_net, teacher_net, head, optimizer,\n                     global_crops, local_crops):\n    # Teacher forward on global crops only (no gradients)\n    with torch.no_grad():\n        t_outs = [teacher_net(gc) for gc in global_crops]\n\n    # Student forward on ALL crops (global + local)\n    all_crops = global_crops + local_crops\n    s_outs    = [student_net(c) for c in all_crops]\n\n    # Loss: each student crop predicts each teacher crop\u0027s distribution\n    loss   = torch.tensor(0.0)\n    n_pairs = 0\n    for s_out in s_outs:\n        for t_out in t_outs:\n            loss = loss + head.dino_loss(s_out, t_out)\n            n_pairs += 1\n    loss = loss / n_pairs\n\n    optimizer.zero_grad()\n    loss.backward()\n    nn.utils.clip_grad_norm_(student_net.parameters(), 3.0)\n    optimizer.step()\n    head.update_center(torch.cat(t_outs).detach())\n    return loss.item()"},{"type":"heading","level":2,"content":"DINO Attention Maps"},{"type":"text","content":"The most striking emergent property of DINO-pretrained ViTs is that the self-attention maps in the last transformer block align closely with semantic object masks — despite no segmentation supervision. Each attention head attends to different object parts. By thresholding the CLS-to-patch attention, one obtains near-ground-truth object masks from a model trained only with image-level self-supervision."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport numpy as np\nimport matplotlib.pyplot as plt\n\ndef extract_dino_attention(model, img, patch_size=8, threshold_pct=60):\n    # Extract CLS-\u003epatch self-attention from the last ViT block\n    model.eval()\n    attn_store = {}\n\n    def hook_fn(module, inp, out):\n        # MultiheadAttention returns (output, attn_weights) when need_weights=True\n        attn_store[\u0027attn\u0027] = out[1]\n\n    handle = model.blocks[-1].attn.register_forward_hook(hook_fn)\n\n    with torch.no_grad():\n        _ = model(img.unsqueeze(0))\n    handle.remove()\n\n    # attn: [1, num_heads, N+1, N+1] -\u003e CLS row -\u003e [num_heads, N]\n    attn = attn_store[\u0027attn\u0027][0, :, 0, 1:]  # remove cls-to-cls\n    h = w = int(attn.shape[-1] ** 0.5)\n    attn = attn.reshape(-1, 1, h, w)        # [num_heads, 1, h, w]\n\n    # Upsample to original image resolution\n    img_h, img_w = img.shape[-2], img.shape[-1]\n    attn_up = F.interpolate(attn, size=(img_h, img_w), mode=\u0027bilinear\u0027, align_corners=False)\n    attn_up = attn_up.squeeze(1).cpu().numpy()  # [num_heads, H, W]\n\n    # Threshold each head to get binary foreground masks\n    masks = np.stack([\n        a \u003e np.percentile(a, threshold_pct) for a in attn_up\n    ])\n    return attn_up, masks   # (raw attention, binary masks)"},{"type":"heading","level":2,"content":"Evaluation — k-NN Classification"},{"type":"text","content":"DINO features are remarkably good for k-nearest-neighbor (k-NN) classification — no linear layer or fine-tuning required. Features are extracted from the frozen backbone, L2-normalized, and the label of the k=20 nearest training neighbors is used for prediction. DINO ViT-S/8 achieves 74.5% top-1 k-NN accuracy on ImageNet entirely without labels, rivaling supervised models from a few years prior."},{"type":"list","ordered":false,"items":["DINO ViT-S/8: 74.5% k-NN top-1 on ImageNet (no labels, no linear layer)","DINO ViT-B/8: 77.3% k-NN top-1 — strong enough for many retrieval applications","k-NN probe is a direct measure of feature quality: no learned classifier can compensate for bad features","Features are L2-normalized before k-NN search; cosine similarity used as the distance metric","DINOv2 (2023) scales this to 86.1% k-NN top-1 with curated data and larger models"]},{"type":"heading","level":2,"content":"DINO vs Contrastive Methods"},{"type":"text","content":"DINO belongs to the self-distillation family (along with BYOL and EMA-based methods) rather than contrastive learning (SimCLR, MoCo). Contrastive methods require explicit negative pairs to prevent collapse; distillation-based methods rely on architectural asymmetry and center/sharpen mechanisms instead. The table compares DINO with two strong contrastive baselines."},{"type":"table","headers":["Method","Backbone","Multi-crop","Teacher EMA","k-NN Top-1","Attention Map Quality"],"rows":[["DINO","ViT-S/8","Yes (2G + 6L)","Yes (m=0.996→1.0)","74.5%","Excellent (semantic segmentation)"],["MoCo v3","ViT-B/16","No (2 views)","No (momentum encoder separate)","73.2%","Moderate (class-level)"],["SimCLR v2","ResNet-152","No (2 views)","No","63.0%","Poor (texture-biased)"]]},{"type":"heading","level":2,"content":"From DINO to DINOv2"},{"type":"text","content":"DINOv2 (Oquab et al. 2023) scales DINO by curating a large 142M-image dataset (LVD-142M) from the internet, combining DINO\u0027s self-distillation loss with a patch-level masked image modeling loss (similar to iBOT), and training larger models (ViT-g/14). The result is a universal visual feature extractor: DINOv2 ViT-g achieves 86.5% linear probing on ImageNet and 86.1% k-NN, matching many supervised models on dense prediction tasks without any fine-tuning."},{"type":"text","content":"The DINO lineage — DINO → DINOv2 — demonstrates that self-supervised visual pre-training can produce general-purpose features that transfer effectively across depth estimation, semantic segmentation, and image retrieval without task-specific fine-tuning, representing a significant step toward foundation models for vision."}]"
---
# DINO — Self-Distillation Without Labels

DINO (Self-DIstillation with NO labels) by Caron et al. (2021) showed that self-supervised ViT features trained with knowledge distillation between a student and an EMA teacher develop emergent properties absent in supervised models — most strikingly, attention maps that align precisely with semantic object boundaries without ever seeing a segmentation label.

## Self-Distillation Concept

DINO uses a student-teacher framework where both networks share the same ViT architecture. The teacher is an exponential moving average (EMA) of the student's weights — it never receives gradients directly. The student is trained to predict the teacher's output distribution for different augmented views of the same image. Because the teacher is a smoothed version of the student, this is called self-distillation.

## Teacher EMA Update

The teacher's parameters are updated via EMA with a momentum coefficient m that is annealed from 0.996 toward 1.0 during training using a cosine schedule. Higher momentum (m → 1.0) means the teacher changes more slowly — providing a stable training target. The student is updated via standard gradient descent; the teacher receives no gradient signal.

```python
import torch
import torch.nn as nn
import numpy as np
import copy

class DINOTeacherUpdater:
    def __init__(self, student, teacher, base_momentum=0.996):
        self.student       = student
        self.teacher       = teacher
        self.base_momentum = base_momentum
        # Initialize teacher from student weights; disable gradients
        self.teacher.load_state_dict(student.state_dict())
        for p in self.teacher.parameters():
            p.requires_grad_(False)

    def update(self, epoch, max_epochs):
        # Momentum increases from base_momentum to 1.0 via cosine schedule
        m = 1.0 - (1.0 - self.base_momentum) * (
            np.cos(np.pi * epoch / max_epochs) + 1.0
        ) / 2.0

        with torch.no_grad():
            for s_p, t_p in zip(
                self.student.parameters(), self.teacher.parameters()
            ):
                t_p.data.mul_(m).add_((1.0 - m) * s_p.data)

    @torch.no_grad()
    def hard_copy(self):
        # Copy student weights directly to teacher (used at initialization)
        for s_p, t_p in zip(
            self.student.parameters(), self.teacher.parameters()
        ):
            t_p.data.copy_(s_p.data)

# Example: update teacher after each optimizer step
# updater = DINOTeacherUpdater(student, teacher)
# for epoch in range(max_epochs):
#     ... train student ...
#     updater.update(epoch, max_epochs)
```

## Centering and Sharpening

Without any collapse prevention, self-distillation quickly collapses to a trivial solution where both student and teacher output a constant distribution. DINO uses two complementary mechanisms: centering (subtract a running mean from teacher logits to prevent one dimension from dominating) and sharpening (low temperature on the teacher to produce peaked distributions that carry a meaningful training signal).

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class DINOHead(nn.Module):
    def __init__(self, in_dim, out_dim=65536, center_momentum=0.9):
        super().__init__()
        self.mlp = nn.Sequential(
            nn.Linear(in_dim, 2048), nn.GELU(),
            nn.Linear(2048, 2048), nn.GELU(),
            nn.Linear(2048, out_dim, bias=False)
        )
        self.register_buffer('center', torch.zeros(1, out_dim))
        self.center_momentum = center_momentum

    @torch.no_grad()
    def update_center(self, teacher_output):
        # EMA update: subtract running mean to prevent mode collapse
        batch_center = teacher_output.mean(dim=0, keepdim=True)
        self.center = (
            self.center * self.center_momentum
            + batch_center * (1 - self.center_momentum)
        )

    def teacher_softmax(self, x, temp=0.04):
        # Subtract center, apply low temperature -> sharp peaked distribution
        return F.softmax((x - self.center) / temp, dim=-1)

    def student_log_softmax(self, x, temp=0.1):
        # Higher temperature for student -> softer distribution
        return F.log_softmax(x / temp, dim=-1)

    def dino_loss(self, student_out, teacher_out):
        # Cross-entropy H(teacher_sharp, student): student predicts teacher
        t_probs  = self.teacher_softmax(teacher_out)
        s_logp   = self.student_log_softmax(student_out)
        return -(t_probs * s_logp).sum(dim=-1).mean()
```

> **Collapse Prevention is Critical**: Without centering + sharpening, DINO collapses within the first few thousand iterations: the teacher outputs a uniform distribution (all images map to the same representation). Centering prevents any single dimension from dominating. Sharpening (low teacher temperature τ_t = 0.04) ensures the teacher outputs peaked distributions, giving the student a meaningful target to match. Both are required — centering alone still allows collapse to a uniform distribution.

## Multi-Crop Training Strategy

DINO uses a multi-crop augmentation strategy: generate 2 global crops (>50% of image area) and 6–8 local crops (<50% area). The teacher sees only the 2 global crops; the student sees all crops. The loss is computed as the cross-entropy from each student output to each teacher output (local→global matching). This teaches the student to predict global context from local views, forcing semantic feature learning.

```python
import torch
import torch.nn as nn
import torchvision.transforms as T

class MultiCropWrapper(nn.Module):
    def __init__(self, backbone, head):
        super().__init__()
        self.backbone = backbone
        self.head     = head

    def forward(self, crops):
        # Batch all crops together for a single efficient forward pass
        all_crops = torch.cat(crops, dim=0)           # [sum(B), C, H, W]
        features  = self.backbone(all_crops)          # [sum(B), D]
        output    = self.head.mlp(features)           # [sum(B), out_dim]
        # Split back into per-crop chunks
        return output.split([c.shape[0] for c in crops], dim=0)

def dino_train_step(student_net, teacher_net, head, optimizer,
                     global_crops, local_crops):
    # Teacher forward on global crops only (no gradients)
    with torch.no_grad():
        t_outs = [teacher_net(gc) for gc in global_crops]

    # Student forward on ALL crops (global + local)
    all_crops = global_crops + local_crops
    s_outs    = [student_net(c) for c in all_crops]

    # Loss: each student crop predicts each teacher crop's distribution
    loss   = torch.tensor(0.0)
    n_pairs = 0
    for s_out in s_outs:
        for t_out in t_outs:
            loss = loss + head.dino_loss(s_out, t_out)
            n_pairs += 1
    loss = loss / n_pairs

    optimizer.zero_grad()
    loss.backward()
    nn.utils.clip_grad_norm_(student_net.parameters(), 3.0)
    optimizer.step()
    head.update_center(torch.cat(t_outs).detach())
    return loss.item()
```

## DINO Attention Maps

The most striking emergent property of DINO-pretrained ViTs is that the self-attention maps in the last transformer block align closely with semantic object masks — despite no segmentation supervision. Each attention head attends to different object parts. By thresholding the CLS-to-patch attention, one obtains near-ground-truth object masks from a model trained only with image-level self-supervision.

```python
import torch
import torch.nn.functional as F
import numpy as np
import matplotlib.pyplot as plt

def extract_dino_attention(model, img, patch_size=8, threshold_pct=60):
    # Extract CLS->patch self-attention from the last ViT block
    model.eval()
    attn_store = {}

    def hook_fn(module, inp, out):
        # MultiheadAttention returns (output, attn_weights) when need_weights=True
        attn_store['attn'] = out[1]

    handle = model.blocks[-1].attn.register_forward_hook(hook_fn)

    with torch.no_grad():
        _ = model(img.unsqueeze(0))
    handle.remove()

    # attn: [1, num_heads, N+1, N+1] -> CLS row -> [num_heads, N]
    attn = attn_store['attn'][0, :, 0, 1:]  # remove cls-to-cls
    h = w = int(attn.shape[-1] ** 0.5)
    attn = attn.reshape(-1, 1, h, w)        # [num_heads, 1, h, w]

    # Upsample to original image resolution
    img_h, img_w = img.shape[-2], img.shape[-1]
    attn_up = F.interpolate(attn, size=(img_h, img_w), mode='bilinear', align_corners=False)
    attn_up = attn_up.squeeze(1).cpu().numpy()  # [num_heads, H, W]

    # Threshold each head to get binary foreground masks
    masks = np.stack([
        a > np.percentile(a, threshold_pct) for a in attn_up
    ])
    return attn_up, masks   # (raw attention, binary masks)
```

## Evaluation — k-NN Classification

DINO features are remarkably good for k-nearest-neighbor (k-NN) classification — no linear layer or fine-tuning required. Features are extracted from the frozen backbone, L2-normalized, and the label of the k=20 nearest training neighbors is used for prediction. DINO ViT-S/8 achieves 74.5% top-1 k-NN accuracy on ImageNet entirely without labels, rivaling supervised models from a few years prior.

- DINO ViT-S/8: 74.5% k-NN top-1 on ImageNet (no labels, no linear layer)
- DINO ViT-B/8: 77.3% k-NN top-1 — strong enough for many retrieval applications
- k-NN probe is a direct measure of feature quality: no learned classifier can compensate for bad features
- Features are L2-normalized before k-NN search; cosine similarity used as the distance metric
- DINOv2 (2023) scales this to 86.1% k-NN top-1 with curated data and larger models

## DINO vs Contrastive Methods

DINO belongs to the self-distillation family (along with BYOL and EMA-based methods) rather than contrastive learning (SimCLR, MoCo). Contrastive methods require explicit negative pairs to prevent collapse; distillation-based methods rely on architectural asymmetry and center/sharpen mechanisms instead. The table compares DINO with two strong contrastive baselines.

| Method | Backbone | Multi-crop | Teacher EMA | k-NN Top-1 | Attention Map Quality |
| --- | --- | --- | --- | --- | --- |
| DINO | ViT-S/8 | Yes (2G + 6L) | Yes (m=0.996→1.0) | 74.5% | Excellent (semantic segmentation) |
| MoCo v3 | ViT-B/16 | No (2 views) | No (momentum encoder separate) | 73.2% | Moderate (class-level) |
| SimCLR v2 | ResNet-152 | No (2 views) | No | 63.0% | Poor (texture-biased) |

## From DINO to DINOv2

DINOv2 (Oquab et al. 2023) scales DINO by curating a large 142M-image dataset (LVD-142M) from the internet, combining DINO's self-distillation loss with a patch-level masked image modeling loss (similar to iBOT), and training larger models (ViT-g/14). The result is a universal visual feature extractor: DINOv2 ViT-g achieves 86.5% linear probing on ImageNet and 86.1% k-NN, matching many supervised models on dense prediction tasks without any fine-tuning.

The DINO lineage — DINO → DINOv2 — demonstrates that self-supervised visual pre-training can produce general-purpose features that transfer effectively across depth estimation, semantic segmentation, and image retrieval without task-specific fine-tuning, representing a significant step toward foundation models for vision.

