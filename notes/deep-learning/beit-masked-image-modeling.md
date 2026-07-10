---
title: "BEiT — Masked Image Modeling with Visual Tokens"
slug: "beit-masked-image-modeling"
description: "How BEiT (Bao et al. 2022) applies BERT-style masked image modeling using discrete visual tokens from a pretrained dVAE tokenizer, block masking strategy, and the evolution to BEiT v2 and BEiT-3."
tags: ["deep-learning", "self-supervised-learning", "masked-learning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"BEiT (BERT Pre-Training of Image Transformers) by Bao et al. (2022) was one of the first methods to directly apply BERT-style masked prediction to vision. Unlike MAE which reconstructs raw pixels, BEiT predicts discrete visual tokens — quantized semantic codes from a pretrained image tokenizer — making the pretext task more semantically meaningful."},{"type":"heading","level":2,"content":"What is BEiT?"},{"type":"text","content":"BEiT is a two-stage self-supervised pre-training framework for ViT. Stage 1 trains a discrete variational autoencoder (dVAE, borrowed from DALL-E) to produce a vocabulary of 8192 visual tokens. Stage 2 trains a ViT to predict the visual token IDs at masked positions using cross-entropy loss over the 8192-token vocabulary — exactly BERT\u0027s masked language modeling objective, but for images."},{"type":"heading","level":2,"content":"Stage 1 — Discrete Image Tokenizer"},{"type":"text","content":"The image tokenizer is a VQ-VAE (Vector Quantized VAE) or dVAE that maps image patches to discrete code IDs from a fixed vocabulary. Given an input image, the tokenizer produces a grid of integer token IDs (one per patch). These IDs serve as the prediction targets during pre-training. BEiT uses the DALL-E dVAE with vocabulary size 8192, operating at 14x14 = 196 tokens for a 224px image."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass ImageEncoder(nn.Module):\n    # Simplified CNN encoder for the VQ tokenizer\n    def __init__(self, embed_dim=512):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Conv2d(3, 128, 4, 2, 1), nn.ReLU(),\n            nn.Conv2d(128, 256, 4, 2, 1), nn.ReLU(),\n            nn.Conv2d(256, embed_dim, 1)\n        )\n    def forward(self, x): return self.net(x)\n\nclass VQVAETokenizer(nn.Module):\n    def __init__(self, vocab_size=8192, embed_dim=512):\n        super().__init__()\n        self.encoder  = ImageEncoder(embed_dim)\n        self.codebook = nn.Embedding(vocab_size, embed_dim)\n        self.vocab_size = vocab_size\n\n    def forward(self, x):\n        # Encode image to continuous embeddings: [B, D, H, W]\n        z = self.encoder(x)\n        B, D, H, W = z.shape\n\n        # Reshape for distance computation: [B*H*W, D]\n        z_flat = z.permute(0, 2, 3, 1).reshape(-1, D)\n\n        # Compute L2 distances to all codebook entries\n        dists = (\n            z_flat.pow(2).sum(1, keepdim=True)\n            + self.codebook.weight.pow(2).sum(1)\n            - 2 * z_flat @ self.codebook.weight.T\n        )\n        # Assign to nearest codebook entry -\u003e discrete token IDs\n        token_ids = dists.argmin(1).reshape(B, H * W)\n        return token_ids   # [B, N] integer token IDs\n\n    @torch.no_grad()\n    def tokenize(self, x): return self.forward(x)"},{"type":"heading","level":2,"content":"Stage 2 — Blockwise Masking"},{"type":"text","content":"BEiT masks approximately 40% of patches using blockwise (contiguous rectangular) masking rather than random uniform masking. Masking contiguous blocks is harder than masking random scattered patches because adjacent visible patches cannot trivially fill in the missing region. This increases task difficulty and encourages the model to reason about semantic structure."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef blockwise_masking(N, grid_size, mask_ratio=0.40, min_block=4, max_block=25):\n    # Block-wise masking: mask contiguous rectangular regions\n    # Returns binary mask of shape [N], values 1=masked / 0=visible\n    h = w = grid_size\n    mask = torch.zeros(h, w, dtype=torch.bool)\n    target = int(N * mask_ratio)\n    masked_count = 0\n\n    while masked_count \u003c target:\n        # Sample a random block aspect ratio and area\n        aspect      = np.random.uniform(0.3, 1 / 0.3)\n        block_area  = np.random.randint(min_block, max_block + 1)\n        bh = max(1, int(np.sqrt(block_area * aspect)))\n        bw = max(1, int(np.sqrt(block_area / aspect)))\n        bh, bw = min(bh, h), min(bw, w)\n\n        # Random top-left corner within valid range\n        top  = np.random.randint(0, h - bh + 1)\n        left = np.random.randint(0, w - bw + 1)\n        mask[top:top + bh, left:left + bw] = True\n        masked_count = mask.sum().item()\n\n    # Trim any over-masked patches to hit the exact ratio\n    mask_flat = mask.flatten()\n    masked_idx = mask_flat.nonzero(as_tuple=True)[0]\n    if len(masked_idx) \u003e target:\n        n_drop = len(masked_idx) - target\n        drop_idx = masked_idx[torch.randperm(len(masked_idx))[:n_drop]]\n        mask_flat[drop_idx] = False\n\n    return mask_flat.long()  # [N], 1=masked, 0=visible"},{"type":"heading","level":2,"content":"BEiT Pre-training Objective"},{"type":"text","content":"The training objective is cross-entropy over the visual token vocabulary at masked positions. The ViT receives all patches (including mask tokens at masked positions) and must predict the correct token ID for each masked position. This is a classification task over 8192 classes per masked patch, making it fundamentally different from MAE\u0027s regression objective."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass BEiTModel(nn.Module):\n    def __init__(self, vocab_size=8192, patch_size=16, img_size=224,\n                 embed_dim=768, depth=12, num_heads=12):\n        super().__init__()\n        num_patches = (img_size // patch_size) ** 2\n        self.patch_embed = nn.Conv2d(3, embed_dim, patch_size, stride=patch_size)\n        self.cls_token   = nn.Parameter(torch.zeros(1, 1, embed_dim))\n        self.pos_embed   = nn.Parameter(torch.zeros(1, num_patches + 1, embed_dim))\n        self.mask_token  = nn.Parameter(torch.zeros(1, 1, embed_dim))\n        self.blocks = nn.ModuleList([TransformerBlock(embed_dim, num_heads) for _ in range(depth)])\n        self.norm = nn.LayerNorm(embed_dim)\n        self.head = nn.Linear(embed_dim, vocab_size)  # predict over 8192 visual tokens\n\ndef beit_forward(model, imgs, token_ids, mask):\n    # mask: [B, N], 1=masked 0=visible\n    B = imgs.shape[0]\n    x = model.patch_embed(imgs).flatten(2).transpose(1, 2)  # [B, N, D]\n    x = x + model.pos_embed[:, 1:, :]\n\n    # Substitute masked patch embeddings with the learnable mask token\n    mask_expanded = mask.unsqueeze(-1).float()\n    x = x * (1 - mask_expanded) + model.mask_token * mask_expanded\n\n    # Prepend cls token and run ViT blocks\n    cls = model.cls_token.expand(B, -1, -1)\n    x   = torch.cat([cls, x], dim=1)\n    for block in model.blocks:\n        x = block(x)\n    logits = model.head(model.norm(x)[:, 1:, :])   # [B, N, 8192]\n\n    # Cross-entropy only on masked positions\n    loss = F.cross_entropy(logits[mask.bool()], token_ids[mask.bool()])\n    return loss, logits"},{"type":"callout","variant":"info","title":"Semantic vs Pixel Targets","content":"BEiT\u0027s discrete token targets filter out high-frequency pixel noise and focus prediction on semantic content. A patch showing a cat\u0027s eye and a patch showing random texture may look similar in raw pixels but have very different token IDs. This semantic discretization is BEiT\u0027s main advantage over MAE-style pixel prediction, though it comes at the cost of requiring a pre-trained tokenizer."},{"type":"heading","level":2,"content":"Evaluation — Linear Probe"},{"type":"text","content":"Linear probing (training only a linear classifier on frozen features) is a standard way to evaluate the quality of self-supervised representations. Unlike fine-tuning which adapts all weights, linear probing directly measures how linearly separable the learned features are. The following code extracts CLS token features and trains a logistic regression classifier for comparison."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nfrom sklearn.linear_model import LogisticRegression\nfrom sklearn.metrics import accuracy_score\n\ndef extract_cls_features(model, dataloader, device=\u0027cuda\u0027):\n    model.eval()\n    features, labels = [], []\n    with torch.no_grad():\n        for imgs, lbls in dataloader:\n            imgs = imgs.to(device)\n            # Forward pass through frozen backbone — use CLS token as features\n            x = model.patch_embed(imgs).flatten(2).transpose(1, 2)\n            x = x + model.pos_embed[:, 1:, :]\n            cls = model.cls_token.expand(imgs.shape[0], -1, -1)\n            x   = torch.cat([cls, x], dim=1)\n            for block in model.blocks:\n                x = block(x)\n            feats = model.norm(x)[:, 0].cpu().numpy()  # CLS token\n            features.append(feats)\n            labels.append(lbls.numpy())\n    return np.concatenate(features), np.concatenate(labels)\n\ndef linear_probe(model, train_loader, val_loader, device=\u0027cuda\u0027):\n    print(\u0027Extracting train features...\u0027)\n    X_tr, y_tr = extract_cls_features(model, train_loader, device)\n    print(\u0027Extracting val features...\u0027)\n    X_val, y_val = extract_cls_features(model, val_loader, device)\n\n    # L2 normalize (standard practice for ViT features)\n    X_tr  = X_tr  / (np.linalg.norm(X_tr,  axis=1, keepdims=True) + 1e-8)\n    X_val = X_val / (np.linalg.norm(X_val, axis=1, keepdims=True) + 1e-8)\n\n    clf = LogisticRegression(max_iter=1000, C=1.0)\n    clf.fit(X_tr, y_tr)\n    acc = accuracy_score(y_val, clf.predict(X_val))\n    print(f\u0027Linear probe top-1: {acc * 100:.2f}%\u0027)\n    return acc"},{"type":"heading","level":2,"content":"BEiT v2 and BEiT-3"},{"type":"text","content":"BEiT v2 replaces the DALL-E dVAE tokenizer with VQ-KD tokens distilled from a CLIP model, producing more semantically meaningful targets. BEiT-3 unifies vision-language pretraining by treating image patches and text tokens uniformly — both masked with the same objective — enabling a single model to handle image classification, captioning, VQA, and retrieval."},{"type":"list","ordered":false,"items":["BEiT (2022): dVAE tokens from DALL-E, block masking 40%, ViT-L reaches 86.3% ImageNet top-1","BEiT v2 (2022): VQ-KD tokens from CLIP teacher, more semantic targets, improved linear probing","BEiT-3 (2022): multimodal foundation model, treats image patches and text tokens uniformly","All variants require a pre-trained tokenizer — unlike MAE which needs nothing beyond image data"]},{"type":"heading","level":2,"content":"Comparison Table"},{"type":"text","content":"The table below compares BEiT variants against MAE and iGPT (autoregressive pixel prediction) across key design dimensions. Note the trade-off between tokenizer requirement and representation quality."},{"type":"table","headers":["Method","Prediction Target","Mask Ratio","Tokenizer Needed","Masking Strategy","IN-1K Fine-tune Top-1"],"rows":[["BEiT","dVAE visual tokens","40%","Yes (DALL-E dVAE)","Block masking","86.3% (ViT-L)"],["BEiT v2","VQ-KD (CLIP) tokens","40%","Yes (CLIP teacher)","Block masking","87.3% (ViT-L)"],["MAE","Normalized pixels","75%","No","Random masking","87.8% (ViT-H)"],["iGPT","Quantized RGB clusters","N/A (autoregressive)","Yes (k-means colors)","None (autoregressive)","72.0% (iGPT-L)"]]},{"type":"text","content":"BEiT\u0027s tokenizer dependency is both its main cost and its main advantage: the pre-trained tokenizer constrains the model to predict structured semantic codes rather than noisy pixel values, producing features that generalize better to semantic downstream tasks like object detection and dense prediction."}]"
---
# BEiT — Masked Image Modeling with Visual Tokens

BEiT (BERT Pre-Training of Image Transformers) by Bao et al. (2022) was one of the first methods to directly apply BERT-style masked prediction to vision. Unlike MAE which reconstructs raw pixels, BEiT predicts discrete visual tokens — quantized semantic codes from a pretrained image tokenizer — making the pretext task more semantically meaningful.

## What is BEiT?

BEiT is a two-stage self-supervised pre-training framework for ViT. Stage 1 trains a discrete variational autoencoder (dVAE, borrowed from DALL-E) to produce a vocabulary of 8192 visual tokens. Stage 2 trains a ViT to predict the visual token IDs at masked positions using cross-entropy loss over the 8192-token vocabulary — exactly BERT's masked language modeling objective, but for images.

## Stage 1 — Discrete Image Tokenizer

The image tokenizer is a VQ-VAE (Vector Quantized VAE) or dVAE that maps image patches to discrete code IDs from a fixed vocabulary. Given an input image, the tokenizer produces a grid of integer token IDs (one per patch). These IDs serve as the prediction targets during pre-training. BEiT uses the DALL-E dVAE with vocabulary size 8192, operating at 14x14 = 196 tokens for a 224px image.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class ImageEncoder(nn.Module):
    # Simplified CNN encoder for the VQ tokenizer
    def __init__(self, embed_dim=512):
        super().__init__()
        self.net = nn.Sequential(
            nn.Conv2d(3, 128, 4, 2, 1), nn.ReLU(),
            nn.Conv2d(128, 256, 4, 2, 1), nn.ReLU(),
            nn.Conv2d(256, embed_dim, 1)
        )
    def forward(self, x): return self.net(x)

class VQVAETokenizer(nn.Module):
    def __init__(self, vocab_size=8192, embed_dim=512):
        super().__init__()
        self.encoder  = ImageEncoder(embed_dim)
        self.codebook = nn.Embedding(vocab_size, embed_dim)
        self.vocab_size = vocab_size

    def forward(self, x):
        # Encode image to continuous embeddings: [B, D, H, W]
        z = self.encoder(x)
        B, D, H, W = z.shape

        # Reshape for distance computation: [B*H*W, D]
        z_flat = z.permute(0, 2, 3, 1).reshape(-1, D)

        # Compute L2 distances to all codebook entries
        dists = (
            z_flat.pow(2).sum(1, keepdim=True)
            + self.codebook.weight.pow(2).sum(1)
            - 2 * z_flat @ self.codebook.weight.T
        )
        # Assign to nearest codebook entry -> discrete token IDs
        token_ids = dists.argmin(1).reshape(B, H * W)
        return token_ids   # [B, N] integer token IDs

    @torch.no_grad()
    def tokenize(self, x): return self.forward(x)
```

## Stage 2 — Blockwise Masking

BEiT masks approximately 40% of patches using blockwise (contiguous rectangular) masking rather than random uniform masking. Masking contiguous blocks is harder than masking random scattered patches because adjacent visible patches cannot trivially fill in the missing region. This increases task difficulty and encourages the model to reason about semantic structure.

```python
import torch
import numpy as np

def blockwise_masking(N, grid_size, mask_ratio=0.40, min_block=4, max_block=25):
    # Block-wise masking: mask contiguous rectangular regions
    # Returns binary mask of shape [N], values 1=masked / 0=visible
    h = w = grid_size
    mask = torch.zeros(h, w, dtype=torch.bool)
    target = int(N * mask_ratio)
    masked_count = 0

    while masked_count < target:
        # Sample a random block aspect ratio and area
        aspect      = np.random.uniform(0.3, 1 / 0.3)
        block_area  = np.random.randint(min_block, max_block + 1)
        bh = max(1, int(np.sqrt(block_area * aspect)))
        bw = max(1, int(np.sqrt(block_area / aspect)))
        bh, bw = min(bh, h), min(bw, w)

        # Random top-left corner within valid range
        top  = np.random.randint(0, h - bh + 1)
        left = np.random.randint(0, w - bw + 1)
        mask[top:top + bh, left:left + bw] = True
        masked_count = mask.sum().item()

    # Trim any over-masked patches to hit the exact ratio
    mask_flat = mask.flatten()
    masked_idx = mask_flat.nonzero(as_tuple=True)[0]
    if len(masked_idx) > target:
        n_drop = len(masked_idx) - target
        drop_idx = masked_idx[torch.randperm(len(masked_idx))[:n_drop]]
        mask_flat[drop_idx] = False

    return mask_flat.long()  # [N], 1=masked, 0=visible
```

## BEiT Pre-training Objective

The training objective is cross-entropy over the visual token vocabulary at masked positions. The ViT receives all patches (including mask tokens at masked positions) and must predict the correct token ID for each masked position. This is a classification task over 8192 classes per masked patch, making it fundamentally different from MAE's regression objective.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class BEiTModel(nn.Module):
    def __init__(self, vocab_size=8192, patch_size=16, img_size=224,
                 embed_dim=768, depth=12, num_heads=12):
        super().__init__()
        num_patches = (img_size // patch_size) ** 2
        self.patch_embed = nn.Conv2d(3, embed_dim, patch_size, stride=patch_size)
        self.cls_token   = nn.Parameter(torch.zeros(1, 1, embed_dim))
        self.pos_embed   = nn.Parameter(torch.zeros(1, num_patches + 1, embed_dim))
        self.mask_token  = nn.Parameter(torch.zeros(1, 1, embed_dim))
        self.blocks = nn.ModuleList([TransformerBlock(embed_dim, num_heads) for _ in range(depth)])
        self.norm = nn.LayerNorm(embed_dim)
        self.head = nn.Linear(embed_dim, vocab_size)  # predict over 8192 visual tokens

def beit_forward(model, imgs, token_ids, mask):
    # mask: [B, N], 1=masked 0=visible
    B = imgs.shape[0]
    x = model.patch_embed(imgs).flatten(2).transpose(1, 2)  # [B, N, D]
    x = x + model.pos_embed[:, 1:, :]

    # Substitute masked patch embeddings with the learnable mask token
    mask_expanded = mask.unsqueeze(-1).float()
    x = x * (1 - mask_expanded) + model.mask_token * mask_expanded

    # Prepend cls token and run ViT blocks
    cls = model.cls_token.expand(B, -1, -1)
    x   = torch.cat([cls, x], dim=1)
    for block in model.blocks:
        x = block(x)
    logits = model.head(model.norm(x)[:, 1:, :])   # [B, N, 8192]

    # Cross-entropy only on masked positions
    loss = F.cross_entropy(logits[mask.bool()], token_ids[mask.bool()])
    return loss, logits
```

> **Semantic vs Pixel Targets**: BEiT's discrete token targets filter out high-frequency pixel noise and focus prediction on semantic content. A patch showing a cat's eye and a patch showing random texture may look similar in raw pixels but have very different token IDs. This semantic discretization is BEiT's main advantage over MAE-style pixel prediction, though it comes at the cost of requiring a pre-trained tokenizer.

## Evaluation — Linear Probe

Linear probing (training only a linear classifier on frozen features) is a standard way to evaluate the quality of self-supervised representations. Unlike fine-tuning which adapts all weights, linear probing directly measures how linearly separable the learned features are. The following code extracts CLS token features and trains a logistic regression classifier for comparison.

```python
import torch
import numpy as np
from sklearn.linear_model import LogisticRegression
from sklearn.metrics import accuracy_score

def extract_cls_features(model, dataloader, device='cuda'):
    model.eval()
    features, labels = [], []
    with torch.no_grad():
        for imgs, lbls in dataloader:
            imgs = imgs.to(device)
            # Forward pass through frozen backbone — use CLS token as features
            x = model.patch_embed(imgs).flatten(2).transpose(1, 2)
            x = x + model.pos_embed[:, 1:, :]
            cls = model.cls_token.expand(imgs.shape[0], -1, -1)
            x   = torch.cat([cls, x], dim=1)
            for block in model.blocks:
                x = block(x)
            feats = model.norm(x)[:, 0].cpu().numpy()  # CLS token
            features.append(feats)
            labels.append(lbls.numpy())
    return np.concatenate(features), np.concatenate(labels)

def linear_probe(model, train_loader, val_loader, device='cuda'):
    print('Extracting train features...')
    X_tr, y_tr = extract_cls_features(model, train_loader, device)
    print('Extracting val features...')
    X_val, y_val = extract_cls_features(model, val_loader, device)

    # L2 normalize (standard practice for ViT features)
    X_tr  = X_tr  / (np.linalg.norm(X_tr,  axis=1, keepdims=True) + 1e-8)
    X_val = X_val / (np.linalg.norm(X_val, axis=1, keepdims=True) + 1e-8)

    clf = LogisticRegression(max_iter=1000, C=1.0)
    clf.fit(X_tr, y_tr)
    acc = accuracy_score(y_val, clf.predict(X_val))
    print(f'Linear probe top-1: {acc * 100:.2f}%')
    return acc
```

## BEiT v2 and BEiT-3

BEiT v2 replaces the DALL-E dVAE tokenizer with VQ-KD tokens distilled from a CLIP model, producing more semantically meaningful targets. BEiT-3 unifies vision-language pretraining by treating image patches and text tokens uniformly — both masked with the same objective — enabling a single model to handle image classification, captioning, VQA, and retrieval.

- BEiT (2022): dVAE tokens from DALL-E, block masking 40%, ViT-L reaches 86.3% ImageNet top-1
- BEiT v2 (2022): VQ-KD tokens from CLIP teacher, more semantic targets, improved linear probing
- BEiT-3 (2022): multimodal foundation model, treats image patches and text tokens uniformly
- All variants require a pre-trained tokenizer — unlike MAE which needs nothing beyond image data

## Comparison Table

The table below compares BEiT variants against MAE and iGPT (autoregressive pixel prediction) across key design dimensions. Note the trade-off between tokenizer requirement and representation quality.

| Method | Prediction Target | Mask Ratio | Tokenizer Needed | Masking Strategy | IN-1K Fine-tune Top-1 |
| --- | --- | --- | --- | --- | --- |
| BEiT | dVAE visual tokens | 40% | Yes (DALL-E dVAE) | Block masking | 86.3% (ViT-L) |
| BEiT v2 | VQ-KD (CLIP) tokens | 40% | Yes (CLIP teacher) | Block masking | 87.3% (ViT-L) |
| MAE | Normalized pixels | 75% | No | Random masking | 87.8% (ViT-H) |
| iGPT | Quantized RGB clusters | N/A (autoregressive) | Yes (k-means colors) | None (autoregressive) | 72.0% (iGPT-L) |

BEiT's tokenizer dependency is both its main cost and its main advantage: the pre-trained tokenizer constrains the model to predict structured semantic codes rather than noisy pixel values, producing features that generalize better to semantic downstream tasks like object detection and dense prediction.

