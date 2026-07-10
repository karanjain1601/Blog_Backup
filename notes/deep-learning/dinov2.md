---
title: "DINOv2 — Curated Data and Improved SSL for Universal Features"
slug: "dinov2"
description: "DINOv2 (Oquab et al. 2023) scales DINO with a carefully curated 142M-image dataset, adds iBOT masked image modeling and SwAV regularization, and produces frozen features that achieve state-of-the-art performance on depth estimation, segmentation, and classification via simple linear probes."
tags: ["deep-learning", "self-supervised-learning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"DINOv2 (Oquab et al. 2023) asked a simple question: what happens to self-supervised visual features when you fix the data and training recipe rather than just scaling the model? The answer was striking — frozen DINOv2 features outperform supervised ViT-L on depth estimation and match it on segmentation using nothing more than a single linear layer. The key innovations are a curated 142M-image dataset (LVD-142M), the combination of DINO + iBOT + SwAV objectives, and careful stabilisation tricks that allow training ViT-g (1B parameters) to completion."},{"type":"heading","level":2,"content":"Dataset Curation — LVD-142M"},{"type":"text","content":"Prior self-supervised methods trained on ImageNet-1K (1.28M images) or uncurated internet crawls. DINOv2 proposes a middle path: harvest images from the internet, then aggressively filter for quality and diversity. Starting from 1.2B candidate images, the pipeline applies: (1) deduplication — remove near-duplicates using copy-detection hashing; (2) retrieval-based curation — use ImageNet-22K as seeds, retrieve nearest neighbours from the web pool using a pretrained SSL model, then threshold by similarity; (3) leakage prevention — deduplicate against downstream test sets (ImageNet val, ADE20K, etc.) to ensure fair evaluation. The result is LVD-142M: 142M high-quality, diverse, non-leaking images."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport numpy as np\nfrom sklearn.preprocessing import normalize\n\n\ndef extract_features_for_dedup(model, dataloader, device=\u0027cuda\u0027):\n    \"\"\"Extract L2-normalised embeddings for near-duplicate detection.\"\"\"\n    model.eval()\n    all_feats, all_ids = [], []\n    with torch.no_grad():\n        for imgs, ids in dataloader:\n            feats = model(imgs.to(device))        # (B, D)\n            feats = F.normalize(feats, dim=1)     # unit sphere\n            all_feats.append(feats.cpu().numpy())\n            all_ids.extend(ids)\n    return np.vstack(all_feats), all_ids\n\n\ndef near_duplicate_removal(features, ids, threshold=0.95):\n    \"\"\"Remove near-duplicates: cosine-similarity \u003e threshold.\n    Returns list of retained image ids.\n    Strategy: greedy — keep first occurrence, remove later duplicates.\n    \"\"\"\n    features = normalize(features, axis=1)  # ensure unit norm\n    n = len(features)\n    removed = set()\n    retained = []\n    for i in range(n):\n        if i in removed:\n            continue\n        retained.append(ids[i])\n        # Vectorised cosine similarity: feat_i dot all_j\n        sims = features[i] @ features[i+1:].T   # (n-i-1,)\n        dup_offsets = np.where(sims \u003e threshold)[0]\n        for off in dup_offsets:\n            removed.add(i + 1 + off)\n    return retained\n\n\ndef quality_filter(scores, ids, min_score=0.5):\n    \"\"\"Keep images whose aesthetic/quality score exceeds threshold.\"\"\"\n    return [id_ for id_, s in zip(ids, scores) if s \u003e= min_score]\n\n\nprint(\u0027Pipeline: extract -\u003e dedup (cosine \u003e 0.95) -\u003e quality filter -\u003e LVD-142M\u0027)"},{"type":"heading","level":2,"content":"iBOT — Masked Image Modeling with Online Tokenizer"},{"type":"text","content":"Standard DINO predicts global CLS token representations across augmented views. iBOT (Image BERT pre-training with Online Tokenizer, Zhou et al. 2022) extends this to patch-level tokens. The teacher network generates patch-level token targets dynamically — there is no fixed discrete tokenizer (unlike BEiT, which uses a pretrained dVAE). Masked patches in the student view must match the corresponding teacher patch tokens. DINOv2 adopts iBOT\u0027s masking as an additional objective alongside the global DINO loss: L_total = L_DINO + λ·L_iBOT + μ·L_SwAV."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\n\ndef ibot_loss(student_patch_tokens, teacher_patch_tokens, mask, temp_s=0.1, temp_t=0.04):\n    \"\"\"iBOT masked image modeling loss.\n    student_patch_tokens: (B, N, D) — student ViT patch outputs\n    teacher_patch_tokens: (B, N, D) — teacher ViT patch outputs (stop-grad)\n    mask: (B, N) bool — True for masked positions to predict\n    \"\"\"\n    # Softmax-based cross-entropy in token probability space\n    # Teacher provides soft targets (sharpened); student predicts from context\n    s = student_patch_tokens[mask]   # (M, D) — masked positions only\n    t = teacher_patch_tokens[mask]   # (M, D)\n\n    # Compute soft targets from teacher (sinkhorn-normalised or simple softmax)\n    t_probs = F.softmax(t / temp_t, dim=-1).detach()   # (M, D) soft targets\n    s_log_probs = F.log_softmax(s / temp_s, dim=-1)    # (M, D)\n\n    loss = -(t_probs * s_log_probs).sum(dim=-1).mean()\n    return loss\n\n\ndef random_block_mask(B, N_patches, mask_ratio=0.15, device=\u0027cpu\u0027):\n    \"\"\"Sample a random mask for iBOT: mask_ratio fraction of patch tokens.\"\"\"\n    num_mask = int(N_patches * mask_ratio)\n    masks = torch.zeros(B, N_patches, dtype=torch.bool, device=device)\n    for i in range(B):\n        idx = torch.randperm(N_patches, device=device)[:num_mask]\n        masks[i, idx] = True\n    return masks\n\n\n# Demo: random masked patches, random token vectors\nB, N, D = 4, 196, 768   # ViT-B: 14x14=196 patches, dim=768\nstudent_tok = torch.randn(B, N, D)\nteacher_tok = torch.randn(B, N, D)\nmask = random_block_mask(B, N, mask_ratio=0.15)\nloss = ibot_loss(student_tok, teacher_tok, mask)\nprint(f\u0027iBOT loss: {loss.item():.4f}  |  masked patches: {mask.sum().item()}\u0027)"},{"type":"heading","level":2,"content":"Training Objectives — DINO + iBOT + SwAV Regularizer"},{"type":"text","content":"DINOv2 combines three complementary self-supervised objectives. DINO provides global view consistency: the student\u0027s CLS token must match the teacher\u0027s CLS token across different augmented views. iBOT provides local patch-level prediction: student patches at masked positions must predict teacher patch tokens. The SwAV regularizer (Caron et al. 2020) uses online clustering to ensure that the feature space remains uniformly spread — preventing feature collapse without relying on the batch contrastive term. The three losses are weighted and summed: L = L_DINO + 0.5·L_iBOT + 0.1·L_SwAV."},{"type":"heading","level":2,"content":"Training Scale and Infrastructure"},{"type":"text","content":"DINOv2-ViT-g has 1.1 billion parameters and was trained for 500K iterations on LVD-142M using 64 A100 GPUs over approximately 15 days. Stability at this scale required several techniques: stochastic depth (drop path), freezing patch projection for the first few thousand steps, gradient clipping, and Shampoo/AdamW with specific learning rate and weight decay schedules per parameter group (higher weight decay for attention parameters). Flash Attention 2 was used throughout to fit the ViT-g sequence length in memory."},{"type":"list","ordered":false,"items":["ViT-S/B/L/g backbones trained — ViT-g (1B) is the flagship model.","AdamW with β₁=0.9, β₂=0.95, peak LR=0.001, weight decay=0.04 → 0.4 (cosine).","Stochastic depth rate=0.4 for ViT-g to regularize the deep network.","EMA momentum schedule: 0.994 → 1.0 (cosine over training) — teacher tracks student.","64× A100 80GB, ~15 days wall-clock; ViT-L trains in ~3 days on same hardware.","Flash Attention 2 enables ViT-g at batch size 3072 without gradient checkpointing."]},{"type":"heading","level":2,"content":"Linear Probe Evaluation — Frozen Universal Features"},{"type":"text","content":"The defining claim of DINOv2 is that its features are \u0027universal\u0027 — a single frozen backbone with a task-specific linear layer achieves strong performance across diverse dense prediction tasks. This is evaluated with a frozen linear probe: freeze the backbone entirely, extract CLS or patch features, train a linear layer with a standard optimizer. DINOv2-ViT-L achieves 86.5% ImageNet top-1 linear probe — 4% above MAE-ViT-L and within 1% of supervised ViT-L. On depth estimation and ADE20K segmentation the margin over MAE and CLIP is even larger."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.utils.data import DataLoader\nfrom torchvision import datasets, transforms\n\n\ndef build_linear_probe(feat_dim: int, num_classes: int = 1000) -\u003e nn.Module:\n    return nn.Sequential(\n        nn.BatchNorm1d(feat_dim, affine=False, eps=1e-6),\n        nn.Linear(feat_dim, num_classes),\n    )\n\n\ndef run_linear_probe(backbone, probe, train_loader, val_loader,\n                     epochs=20, lr=0.1, device=\u0027cuda\u0027):\n    \"\"\"Freeze backbone; train linear probe only.\"\"\"\n    backbone.eval()\n    for p in backbone.parameters():\n        p.requires_grad_(False)\n\n    optimizer = torch.optim.SGD(probe.parameters(), lr=lr,\n                                momentum=0.9, weight_decay=0.0)\n    scheduler = torch.optim.lr_scheduler.CosineAnnealingLR(optimizer, epochs)\n    criterion = nn.CrossEntropyLoss()\n\n    for epoch in range(epochs):\n        probe.train()\n        for imgs, labels in train_loader:\n            imgs, labels = imgs.to(device), labels.to(device)\n            with torch.no_grad():\n                feats = backbone(imgs)  # (B, feat_dim) — CLS token\n            loss = criterion(probe(feats), labels)\n            optimizer.zero_grad()\n            loss.backward()\n            optimizer.step()\n        scheduler.step()\n\n    # Validation\n    probe.eval()\n    correct = total = 0\n    with torch.no_grad():\n        for imgs, labels in val_loader:\n            imgs, labels = imgs.to(device), labels.to(device)\n            preds = probe(backbone(imgs)).argmax(1)\n            correct += (preds == labels).sum().item()\n            total += labels.size(0)\n    return correct / total\n\n\nprint(\u0027DINOv2 linear probe: freeze backbone, BatchNorm + Linear head only.\u0027)\nprint(\u0027DINOv2-ViT-L achieves ~86.5% top-1 with this simple protocol.\u0027)"},{"type":"heading","level":2,"content":"Depth Estimation with Frozen DINOv2 Features"},{"type":"text","content":"Monocular depth estimation is one of the most demanding dense prediction tasks because it requires both local spatial accuracy and global scene understanding. DINOv2 patch features (14×14 spatial grid for a 224×224 image) can be fed directly into a single linear layer trained to predict a dense depth map. This is a remarkable demonstration of feature quality: no task-specific encoder training, no decoder, just a linear map from frozen patch tokens to depth values. DINOv2-ViT-L with this protocol outperforms many specialized depth networks fine-tuned end-to-end."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\n\nclass DINOv2DepthLinear(nn.Module):\n    \"\"\"Single linear layer depth estimator on frozen DINOv2 patch tokens.\"\"\"\n\n    def __init__(self, backbone, patch_dim: int = 1024, output_h: int = 14,\n                 output_w: int = 14):\n        super().__init__()\n        self.backbone = backbone\n        self.output_h = output_h\n        self.output_w = output_w\n        # Freeze backbone\n        for p in self.backbone.parameters():\n            p.requires_grad_(False)\n        # One linear layer: patch_dim -\u003e 1 depth value per patch\n        self.depth_head = nn.Linear(patch_dim, 1)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        \"\"\"x: (B, 3, H, W) -\u003e depth: (B, 1, H_out, W_out).\"\"\"\n        with torch.no_grad():\n            # DINOv2 returns dict with \u0027x_norm_patchtokens\u0027: (B, N_patches, D)\n            out = self.backbone.forward_features(x)\n            patch_tokens = out[\u0027x_norm_patchtokens\u0027]   # (B, 196, 1024) for ViT-L\n        depth = self.depth_head(patch_tokens)           # (B, 196, 1)\n        B, N, _ = depth.shape\n        depth = depth.view(B, self.output_h, self.output_w, 1)\n        depth = depth.permute(0, 3, 1, 2)               # (B, 1, H, W)\n        # Upsample to input resolution\n        depth = F.interpolate(depth, scale_factor=16,\n                              mode=\u0027bilinear\u0027, align_corners=False)\n        return depth\n\n\nprint(\u0027DINOv2 depth probe: single nn.Linear on patch tokens -\u003e bilinear upsample.\u0027)\nprint(\u0027ViT-L patch tokens: (B, 196, 1024) for 224x224 input with 14x14 patches.\u0027)"},{"type":"callout","variant":"insight","title":"Why DINOv2 Beats MAE on Frozen Evaluation","content":"MAE is optimised to reconstruct pixel values from visible patches — it never sees a discriminative signal. Its features require fine-tuning to reach competitive accuracy. DINOv2 combines DINO (global discriminative) + iBOT (patch discriminative) + SwAV (cluster regularisation), ensuring the frozen representation is both spatially rich and globally semantic. On linear probe, DINOv2-ViT-L exceeds MAE-ViT-L by ~4% on ImageNet and by larger margins on dense tasks."},{"type":"heading","level":2,"content":"DINOv2 vs Prior Methods"},{"type":"table","headers":["Method","Pretraining Obj.","Data","k-NN Top-1","Depth RMSE (↓)","Seg. mIoU","Classification Linear"],"rows":[["MAE ViT-L","Pixel reconstruction","ImageNet-1K","56.5%","0.339","45.4","75.8%"],["CLIP ViT-L","Image-text contrastive","LAION-2B","75.3%","0.312","48.1","85.4%"],["Supervised ViT-L","Cross-entropy","ImageNet-22K","—","0.294","53.2","87.3%"],["DINOv2 ViT-L","DINO+iBOT+SwAV","LVD-142M","81.1%","0.271","53.0","86.5%"],["DINOv2 ViT-g","DINO+iBOT+SwAV","LVD-142M","83.5%","0.258","54.9","87.1%"]]},{"type":"text","content":"DINOv2-ViT-g surpasses supervised ViT-L on depth and nearly matches it on segmentation — using only frozen features and a linear head. This represents a qualitative shift: for deployment scenarios where fine-tuning is expensive, DINOv2 provides a plug-and-play feature extractor competitive with supervised pretraining. Its primary limitation is training compute: 64 A100s for 15 days is beyond most research labs, though smaller DINOv2 variants (ViT-S, ViT-B) are practical to distil or fine-tune."},{"type":"list","ordered":false,"items":["DINOv2 ViT-S/B/L/g are open-sourced on HuggingFace — use torch.hub.load(\u0027facebookresearch/dinov2\u0027, \u0027dinov2_vitl14\u0027).","forward_features() returns both CLS token and patch tokens — use patch tokens for dense tasks.","DINOv2 features generalize to medical imaging and satellite imagery without any domain-specific fine-tuning.","Inferior to fine-tuned supervised models on some tasks — frozen evaluation is not the end game.","LVD-142M curation code is open-source; the curated dataset itself is not distributed due to licensing."]}]"
---
# DINOv2 — Curated Data and Improved SSL for Universal Features

DINOv2 (Oquab et al. 2023) asked a simple question: what happens to self-supervised visual features when you fix the data and training recipe rather than just scaling the model? The answer was striking — frozen DINOv2 features outperform supervised ViT-L on depth estimation and match it on segmentation using nothing more than a single linear layer. The key innovations are a curated 142M-image dataset (LVD-142M), the combination of DINO + iBOT + SwAV objectives, and careful stabilisation tricks that allow training ViT-g (1B parameters) to completion.

## Dataset Curation — LVD-142M

Prior self-supervised methods trained on ImageNet-1K (1.28M images) or uncurated internet crawls. DINOv2 proposes a middle path: harvest images from the internet, then aggressively filter for quality and diversity. Starting from 1.2B candidate images, the pipeline applies: (1) deduplication — remove near-duplicates using copy-detection hashing; (2) retrieval-based curation — use ImageNet-22K as seeds, retrieve nearest neighbours from the web pool using a pretrained SSL model, then threshold by similarity; (3) leakage prevention — deduplicate against downstream test sets (ImageNet val, ADE20K, etc.) to ensure fair evaluation. The result is LVD-142M: 142M high-quality, diverse, non-leaking images.

```python
import torch
import torch.nn.functional as F
import numpy as np
from sklearn.preprocessing import normalize


def extract_features_for_dedup(model, dataloader, device='cuda'):
    """Extract L2-normalised embeddings for near-duplicate detection."""
    model.eval()
    all_feats, all_ids = [], []
    with torch.no_grad():
        for imgs, ids in dataloader:
            feats = model(imgs.to(device))        # (B, D)
            feats = F.normalize(feats, dim=1)     # unit sphere
            all_feats.append(feats.cpu().numpy())
            all_ids.extend(ids)
    return np.vstack(all_feats), all_ids


def near_duplicate_removal(features, ids, threshold=0.95):
    """Remove near-duplicates: cosine-similarity > threshold.
    Returns list of retained image ids.
    Strategy: greedy — keep first occurrence, remove later duplicates.
    """
    features = normalize(features, axis=1)  # ensure unit norm
    n = len(features)
    removed = set()
    retained = []
    for i in range(n):
        if i in removed:
            continue
        retained.append(ids[i])
        # Vectorised cosine similarity: feat_i dot all_j
        sims = features[i] @ features[i+1:].T   # (n-i-1,)
        dup_offsets = np.where(sims > threshold)[0]
        for off in dup_offsets:
            removed.add(i + 1 + off)
    return retained


def quality_filter(scores, ids, min_score=0.5):
    """Keep images whose aesthetic/quality score exceeds threshold."""
    return [id_ for id_, s in zip(ids, scores) if s >= min_score]


print('Pipeline: extract -> dedup (cosine > 0.95) -> quality filter -> LVD-142M')
```

## iBOT — Masked Image Modeling with Online Tokenizer

Standard DINO predicts global CLS token representations across augmented views. iBOT (Image BERT pre-training with Online Tokenizer, Zhou et al. 2022) extends this to patch-level tokens. The teacher network generates patch-level token targets dynamically — there is no fixed discrete tokenizer (unlike BEiT, which uses a pretrained dVAE). Masked patches in the student view must match the corresponding teacher patch tokens. DINOv2 adopts iBOT's masking as an additional objective alongside the global DINO loss: L_total = L_DINO + λ·L_iBOT + μ·L_SwAV.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F


def ibot_loss(student_patch_tokens, teacher_patch_tokens, mask, temp_s=0.1, temp_t=0.04):
    """iBOT masked image modeling loss.
    student_patch_tokens: (B, N, D) — student ViT patch outputs
    teacher_patch_tokens: (B, N, D) — teacher ViT patch outputs (stop-grad)
    mask: (B, N) bool — True for masked positions to predict
    """
    # Softmax-based cross-entropy in token probability space
    # Teacher provides soft targets (sharpened); student predicts from context
    s = student_patch_tokens[mask]   # (M, D) — masked positions only
    t = teacher_patch_tokens[mask]   # (M, D)

    # Compute soft targets from teacher (sinkhorn-normalised or simple softmax)
    t_probs = F.softmax(t / temp_t, dim=-1).detach()   # (M, D) soft targets
    s_log_probs = F.log_softmax(s / temp_s, dim=-1)    # (M, D)

    loss = -(t_probs * s_log_probs).sum(dim=-1).mean()
    return loss


def random_block_mask(B, N_patches, mask_ratio=0.15, device='cpu'):
    """Sample a random mask for iBOT: mask_ratio fraction of patch tokens."""
    num_mask = int(N_patches * mask_ratio)
    masks = torch.zeros(B, N_patches, dtype=torch.bool, device=device)
    for i in range(B):
        idx = torch.randperm(N_patches, device=device)[:num_mask]
        masks[i, idx] = True
    return masks


# Demo: random masked patches, random token vectors
B, N, D = 4, 196, 768   # ViT-B: 14x14=196 patches, dim=768
student_tok = torch.randn(B, N, D)
teacher_tok = torch.randn(B, N, D)
mask = random_block_mask(B, N, mask_ratio=0.15)
loss = ibot_loss(student_tok, teacher_tok, mask)
print(f'iBOT loss: {loss.item():.4f}  |  masked patches: {mask.sum().item()}')
```

## Training Objectives — DINO + iBOT + SwAV Regularizer

DINOv2 combines three complementary self-supervised objectives. DINO provides global view consistency: the student's CLS token must match the teacher's CLS token across different augmented views. iBOT provides local patch-level prediction: student patches at masked positions must predict teacher patch tokens. The SwAV regularizer (Caron et al. 2020) uses online clustering to ensure that the feature space remains uniformly spread — preventing feature collapse without relying on the batch contrastive term. The three losses are weighted and summed: L = L_DINO + 0.5·L_iBOT + 0.1·L_SwAV.

## Training Scale and Infrastructure

DINOv2-ViT-g has 1.1 billion parameters and was trained for 500K iterations on LVD-142M using 64 A100 GPUs over approximately 15 days. Stability at this scale required several techniques: stochastic depth (drop path), freezing patch projection for the first few thousand steps, gradient clipping, and Shampoo/AdamW with specific learning rate and weight decay schedules per parameter group (higher weight decay for attention parameters). Flash Attention 2 was used throughout to fit the ViT-g sequence length in memory.

- ViT-S/B/L/g backbones trained — ViT-g (1B) is the flagship model.
- AdamW with β₁=0.9, β₂=0.95, peak LR=0.001, weight decay=0.04 → 0.4 (cosine).
- Stochastic depth rate=0.4 for ViT-g to regularize the deep network.
- EMA momentum schedule: 0.994 → 1.0 (cosine over training) — teacher tracks student.
- 64× A100 80GB, ~15 days wall-clock; ViT-L trains in ~3 days on same hardware.
- Flash Attention 2 enables ViT-g at batch size 3072 without gradient checkpointing.

## Linear Probe Evaluation — Frozen Universal Features

The defining claim of DINOv2 is that its features are 'universal' — a single frozen backbone with a task-specific linear layer achieves strong performance across diverse dense prediction tasks. This is evaluated with a frozen linear probe: freeze the backbone entirely, extract CLS or patch features, train a linear layer with a standard optimizer. DINOv2-ViT-L achieves 86.5% ImageNet top-1 linear probe — 4% above MAE-ViT-L and within 1% of supervised ViT-L. On depth estimation and ADE20K segmentation the margin over MAE and CLIP is even larger.

```python
import torch
import torch.nn as nn
from torch.utils.data import DataLoader
from torchvision import datasets, transforms


def build_linear_probe(feat_dim: int, num_classes: int = 1000) -> nn.Module:
    return nn.Sequential(
        nn.BatchNorm1d(feat_dim, affine=False, eps=1e-6),
        nn.Linear(feat_dim, num_classes),
    )


def run_linear_probe(backbone, probe, train_loader, val_loader,
                     epochs=20, lr=0.1, device='cuda'):
    """Freeze backbone; train linear probe only."""
    backbone.eval()
    for p in backbone.parameters():
        p.requires_grad_(False)

    optimizer = torch.optim.SGD(probe.parameters(), lr=lr,
                                momentum=0.9, weight_decay=0.0)
    scheduler = torch.optim.lr_scheduler.CosineAnnealingLR(optimizer, epochs)
    criterion = nn.CrossEntropyLoss()

    for epoch in range(epochs):
        probe.train()
        for imgs, labels in train_loader:
            imgs, labels = imgs.to(device), labels.to(device)
            with torch.no_grad():
                feats = backbone(imgs)  # (B, feat_dim) — CLS token
            loss = criterion(probe(feats), labels)
            optimizer.zero_grad()
            loss.backward()
            optimizer.step()
        scheduler.step()

    # Validation
    probe.eval()
    correct = total = 0
    with torch.no_grad():
        for imgs, labels in val_loader:
            imgs, labels = imgs.to(device), labels.to(device)
            preds = probe(backbone(imgs)).argmax(1)
            correct += (preds == labels).sum().item()
            total += labels.size(0)
    return correct / total


print('DINOv2 linear probe: freeze backbone, BatchNorm + Linear head only.')
print('DINOv2-ViT-L achieves ~86.5% top-1 with this simple protocol.')
```

## Depth Estimation with Frozen DINOv2 Features

Monocular depth estimation is one of the most demanding dense prediction tasks because it requires both local spatial accuracy and global scene understanding. DINOv2 patch features (14×14 spatial grid for a 224×224 image) can be fed directly into a single linear layer trained to predict a dense depth map. This is a remarkable demonstration of feature quality: no task-specific encoder training, no decoder, just a linear map from frozen patch tokens to depth values. DINOv2-ViT-L with this protocol outperforms many specialized depth networks fine-tuned end-to-end.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F


class DINOv2DepthLinear(nn.Module):
    """Single linear layer depth estimator on frozen DINOv2 patch tokens."""

    def __init__(self, backbone, patch_dim: int = 1024, output_h: int = 14,
                 output_w: int = 14):
        super().__init__()
        self.backbone = backbone
        self.output_h = output_h
        self.output_w = output_w
        # Freeze backbone
        for p in self.backbone.parameters():
            p.requires_grad_(False)
        # One linear layer: patch_dim -> 1 depth value per patch
        self.depth_head = nn.Linear(patch_dim, 1)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        """x: (B, 3, H, W) -> depth: (B, 1, H_out, W_out)."""
        with torch.no_grad():
            # DINOv2 returns dict with 'x_norm_patchtokens': (B, N_patches, D)
            out = self.backbone.forward_features(x)
            patch_tokens = out['x_norm_patchtokens']   # (B, 196, 1024) for ViT-L
        depth = self.depth_head(patch_tokens)           # (B, 196, 1)
        B, N, _ = depth.shape
        depth = depth.view(B, self.output_h, self.output_w, 1)
        depth = depth.permute(0, 3, 1, 2)               # (B, 1, H, W)
        # Upsample to input resolution
        depth = F.interpolate(depth, scale_factor=16,
                              mode='bilinear', align_corners=False)
        return depth


print('DINOv2 depth probe: single nn.Linear on patch tokens -> bilinear upsample.')
print('ViT-L patch tokens: (B, 196, 1024) for 224x224 input with 14x14 patches.')
```

> **Why DINOv2 Beats MAE on Frozen Evaluation**: MAE is optimised to reconstruct pixel values from visible patches — it never sees a discriminative signal. Its features require fine-tuning to reach competitive accuracy. DINOv2 combines DINO (global discriminative) + iBOT (patch discriminative) + SwAV (cluster regularisation), ensuring the frozen representation is both spatially rich and globally semantic. On linear probe, DINOv2-ViT-L exceeds MAE-ViT-L by ~4% on ImageNet and by larger margins on dense tasks.

## DINOv2 vs Prior Methods

| Method | Pretraining Obj. | Data | k-NN Top-1 | Depth RMSE (↓) | Seg. mIoU | Classification Linear |
| --- | --- | --- | --- | --- | --- | --- |
| MAE ViT-L | Pixel reconstruction | ImageNet-1K | 56.5% | 0.339 | 45.4 | 75.8% |
| CLIP ViT-L | Image-text contrastive | LAION-2B | 75.3% | 0.312 | 48.1 | 85.4% |
| Supervised ViT-L | Cross-entropy | ImageNet-22K | — | 0.294 | 53.2 | 87.3% |
| DINOv2 ViT-L | DINO+iBOT+SwAV | LVD-142M | 81.1% | 0.271 | 53.0 | 86.5% |
| DINOv2 ViT-g | DINO+iBOT+SwAV | LVD-142M | 83.5% | 0.258 | 54.9 | 87.1% |

DINOv2-ViT-g surpasses supervised ViT-L on depth and nearly matches it on segmentation — using only frozen features and a linear head. This represents a qualitative shift: for deployment scenarios where fine-tuning is expensive, DINOv2 provides a plug-and-play feature extractor competitive with supervised pretraining. Its primary limitation is training compute: 64 A100s for 15 days is beyond most research labs, though smaller DINOv2 variants (ViT-S, ViT-B) are practical to distil or fine-tune.

- DINOv2 ViT-S/B/L/g are open-sourced on HuggingFace — use torch.hub.load('facebookresearch/dinov2', 'dinov2_vitl14').
- forward_features() returns both CLS token and patch tokens — use patch tokens for dense tasks.
- DINOv2 features generalize to medical imaging and satellite imagery without any domain-specific fine-tuning.
- Inferior to fine-tuned supervised models on some tasks — frozen evaluation is not the end game.
- LVD-142M curation code is open-source; the curated dataset itself is not distributed due to licensing.

