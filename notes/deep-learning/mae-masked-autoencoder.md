---
title: "MAE — Masked Autoencoders for Vision"
slug: "mae-masked-autoencoder"
description: "Deep dive into MAE (He et al. 2022): masking 75% of image patches, asymmetric encoder-decoder design, normalized pixel reconstruction targets, and comparison with SimMIM, BEiT, and MaskFeat."
tags: ["deep-learning", "self-supervised-learning", "masked-learning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Masked Autoencoders (MAE) by He et al. (2022) demonstrated that a surprisingly simple idea — mask most of an image and reconstruct the missing parts — scales remarkably well for visual pre-training. By masking 75% of patches and using an asymmetric encoder-decoder, MAE achieves strong representations without contrastive pairs, negative samples, or momentum networks."},{"type":"heading","level":2,"content":"What is MAE?"},{"type":"text","content":"MAE is a self-supervised pre-training method for vision transformers (ViT). The core idea mirrors BERT in NLP: randomly mask a subset of input tokens (patches) and train the model to reconstruct the originals. The key insight is that vision data is far more redundant than language — a high masking ratio (75% vs BERT\u0027s 15%) forces the model to learn holistic scene understanding rather than interpolating from nearby visible pixels."},{"type":"heading","level":2,"content":"Patch Masking Strategy"},{"type":"text","content":"MAE divides the input image into non-overlapping patches (typically 16x16 pixels). A random 75% of patches are masked. Crucially, the encoder sees only the remaining 25% — mask tokens are never passed to the encoder. This asymmetric design is the key efficiency win: the encoder processes only a quarter of the patches, yielding a 3–4x speedup over processing all patches."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef random_masking(x, mask_ratio=0.75):\n    # x: [B, N, D] patch embeddings\n    # Returns: visible tokens, binary mask (1=masked), restore indices\n    B, N, D = x.shape\n    keep = int(N * (1 - mask_ratio))  # number of patches to keep\n\n    # Generate per-sample random noise for independent shuffling\n    noise = torch.rand(B, N, device=x.device)\n\n    # Sort patches by noise to get a random permutation\n    ids_shuffle = torch.argsort(noise, dim=1)        # ascending\n    ids_restore = torch.argsort(ids_shuffle, dim=1)  # inverse permutation\n\n    # Keep only the first `keep` patches (lowest noise values)\n    ids_keep = ids_shuffle[:, :keep]\n    x_visible = torch.gather(\n        x, dim=1,\n        index=ids_keep.unsqueeze(-1).expand(-1, -1, D)\n    )\n\n    # Binary mask: 0 = kept, 1 = masked (aligned with ids_restore order)\n    mask = torch.ones(B, N, device=x.device)\n    mask[:, :keep] = 0\n    mask = torch.gather(mask, dim=1, index=ids_restore)\n\n    return x_visible, mask, ids_restore\n\n# Example usage: 196 patches (14x14 grid for 224px image with 16px patches)\n# x = torch.randn(8, 196, 768)  # batch of 8, 196 patches, 768-dim\n# x_vis, mask, ids_restore = random_masking(x, mask_ratio=0.75)\n# x_vis.shape  -\u003e [8, 49, 768]  (only 25% visible)"},{"type":"heading","level":2,"content":"The MAE Encoder"},{"type":"text","content":"The encoder is a standard ViT (e.g., ViT-L with 24 blocks and 1024-dim embeddings) that operates exclusively on visible patches. Positional embeddings are added before masking so the encoder knows spatial positions. No mask tokens enter the encoder — this is what makes it computationally efficient. The encoder produces rich representations for only the visible 25% of patches."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom einops import rearrange\n\nclass TransformerBlock(nn.Module):\n    def __init__(self, dim, heads, mlp_ratio=4.0):\n        super().__init__()\n        self.norm1 = nn.LayerNorm(dim)\n        self.attn = nn.MultiheadAttention(dim, heads, batch_first=True)\n        self.norm2 = nn.LayerNorm(dim)\n        self.mlp = nn.Sequential(\n            nn.Linear(dim, int(dim * mlp_ratio)), nn.GELU(),\n            nn.Linear(int(dim * mlp_ratio), dim)\n        )\n    def forward(self, x):\n        x = x + self.attn(self.norm1(x), self.norm1(x), self.norm1(x))[0]\n        return x + self.mlp(self.norm2(x))\n\nclass MAEEncoder(nn.Module):\n    def __init__(self, img_size=224, patch_size=16, embed_dim=768, depth=12, num_heads=12):\n        super().__init__()\n        self.patch_embed = nn.Conv2d(3, embed_dim, patch_size, stride=patch_size)\n        num_patches = (img_size // patch_size) ** 2\n        self.pos_embed = nn.Parameter(torch.zeros(1, num_patches + 1, embed_dim))\n        self.cls_token  = nn.Parameter(torch.zeros(1, 1, embed_dim))\n        self.blocks = nn.ModuleList([TransformerBlock(embed_dim, num_heads) for _ in range(depth)])\n        self.norm = nn.LayerNorm(embed_dim)\n\n    def forward(self, x, ids_keep):\n        B = x.shape[0]\n        x = rearrange(self.patch_embed(x), \u0027b d h w -\u003e b (h w) d\u0027)\n        x = x + self.pos_embed[:, 1:, :]                                  # spatial pos-embed\n        D = x.shape[-1]\n        x = torch.gather(x, 1, ids_keep.unsqueeze(-1).expand(-1, -1, D)) # keep visible only\n        cls = self.cls_token.expand(B, -1, -1)\n        x = torch.cat([cls, x], dim=1)\n        for block in self.blocks:\n            x = block(x)\n        return self.norm(x)  # [B, 1+keep, D]"},{"type":"heading","level":2,"content":"The MAE Decoder"},{"type":"text","content":"The decoder is intentionally lightweight — only 4 transformer blocks (vs 12+ in the encoder) and a smaller embedding dimension (512 vs 768). It receives encoded visible tokens plus learnable mask tokens inserted at masked positions. Positional embeddings are added so the decoder knows which patches to reconstruct. The output head projects to pixel values for each patch."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass MAEDecoder(nn.Module):\n    def __init__(self, num_patches=196, encoder_dim=768, decoder_dim=512,\n                 depth=4, num_heads=8, patch_size=16):\n        super().__init__()\n        self.decoder_embed = nn.Linear(encoder_dim, decoder_dim)\n        self.mask_token = nn.Parameter(torch.zeros(1, 1, decoder_dim))\n        self.pos_embed  = nn.Parameter(torch.zeros(1, num_patches + 1, decoder_dim))\n        self.blocks = nn.ModuleList([TransformerBlock(decoder_dim, num_heads) for _ in range(depth)])\n        self.norm = nn.LayerNorm(decoder_dim)\n        self.pred = nn.Linear(decoder_dim, patch_size * patch_size * 3)\n\n    def forward(self, x_encoded, ids_restore):\n        x = self.decoder_embed(x_encoded)   # project encoder dim -\u003e decoder dim\n        x_vis = x[:, 1:, :]                 # strip cls token\n        B, n_vis, D = x_vis.shape\n        n_mask = ids_restore.shape[1] - n_vis\n\n        # Expand mask tokens to fill masked positions\n        mask_tokens = self.mask_token.expand(B, n_mask, -1)\n        x_full = torch.cat([x_vis, mask_tokens], dim=1)   # [B, N, D]\n\n        # Unshuffle: restore original patch order using inverse permutation\n        x_full = torch.gather(\n            x_full, 1, ids_restore.unsqueeze(-1).expand(-1, -1, D)\n        )\n        # Add positional embedding (full sequence) and prepend cls token\n        x_full = x_full + self.pos_embed[:, 1:, :]\n        x = torch.cat([x[:, :1, :], x_full], dim=1)\n        for block in self.blocks:\n            x = block(x)\n        x = self.norm(x)\n        return self.pred(x[:, 1:, :])   # [B, N, patch_size^2 * 3]"},{"type":"heading","level":2,"content":"Reconstruction Target"},{"type":"text","content":"Rather than raw pixel values, MAE normalizes each patch\u0027s pixels to zero mean and unit variance before computing the loss. This per-patch normalization improves training stability and final representation quality. The loss is only computed on masked patches — visible patches are ignored. At inference time, predictions can be unnormalized back to RGB for visualization."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nimport matplotlib.pyplot as plt\n\ndef patchify(imgs, patch_size=16):\n    # Convert [B, 3, H, W] images to [B, N, patch_size^2 * 3] patch tokens\n    p = patch_size\n    h = w = imgs.shape[-1] // p\n    x = imgs.reshape(imgs.shape[0], 3, h, p, w, p)\n    x = torch.einsum(\u0027nchpwq-\u003enhwpqc\u0027, x)\n    return x.reshape(imgs.shape[0], h * w, p * p * 3)\n\ndef compute_reconstruction_target(imgs, patch_size=16):\n    # Per-patch mean/std normalization — the MAE reconstruction target\n    target = patchify(imgs, patch_size)\n    mean = target.mean(dim=-1, keepdim=True)\n    std  = target.var(dim=-1, keepdim=True).sqrt().clamp(min=1e-6)\n    return (target - mean) / std\n\ndef unnormalize_for_viz(pred, orig_imgs, patch_size=16):\n    # Reverse patch normalization for visualization\n    target = patchify(orig_imgs, patch_size)\n    mean = target.mean(dim=-1, keepdim=True)\n    std  = target.var(dim=-1, keepdim=True).sqrt().clamp(min=1e-6)\n    return pred * std + mean\n\ndef mae_loss(pred, imgs, mask, patch_size=16):\n    # MSE loss computed only on masked patches\n    target = compute_reconstruction_target(imgs, patch_size)  # [B, N, p^2*3]\n    loss = ((pred - target) ** 2).mean(dim=-1)               # [B, N] per-patch\n    return (loss * mask).sum() / mask.sum()                   # mean over masked"},{"type":"callout","variant":"insight","title":"Why 75% and Not 15%?","content":"BERT masks only 15% of tokens because language is information-dense — removing more destroys most context. Images are far more spatially redundant: adjacent pixels are highly correlated, so low mask ratios allow trivial texture interpolation. The 75% ratio forces the model to reason globally about object structure, yielding semantically richer features. Ablations show performance drops sharply at mask ratios below 60%."},{"type":"heading","level":2,"content":"High Mask Ratio and Why It Works"},{"type":"text","content":"The high mask ratio is simultaneously the efficiency mechanism and the representation-quality mechanism. With only 25% of patches visible, the encoder cannot rely on nearby pixel interpolation — it must learn object-level semantics. Ablations in the original paper confirm that performance degrades significantly at lower mask ratios (40–50%), validating that task difficulty drives representation quality."},{"type":"list","ordered":false,"items":["75% mask ratio: encoder processes 3–4x fewer tokens, giving a significant training speedup","High masking forces holistic understanding of shape, texture, and object structure","No mask tokens in the encoder prevents exploitation of trivial local correlations","Lightweight decoder (4 blocks) can reconstruct from strong encoder representations","Normalized pixel targets (per-patch mean/std) improve training stability vs raw RGB"]},{"type":"heading","level":2,"content":"Comparison with Related Methods"},{"type":"text","content":"MAE sits in a family of masked image modeling (MIM) approaches that differ in reconstruction targets, masking strategies, and architectures. SimMIM uses a similar pixel-prediction target but passes all tokens (including mask tokens) to the encoder. BEiT predicts discrete visual tokens from a pretrained tokenizer. MaskFeat predicts HOG (Histograms of Oriented Gradients) features, a hand-crafted descriptor."},{"type":"table","headers":["Method","Mask Ratio","Reconstruction Target","Encoder Input","IN-1K Fine-tune Top-1"],"rows":[["MAE","75%","Normalized pixel values","Visible patches only","87.8% (ViT-H)"],["SimMIM","60%","Raw pixel values","All patches + mask tokens","84.0% (SwinV2-H)"],["BEiT","40%","Discrete visual tokens (dVAE)","All patches + mask tokens","86.3% (ViT-L)"],["MaskFeat","40%","HOG features","All patches + mask tokens","84.0% (ViT-L)"]]},{"type":"heading","level":2,"content":"Fine-tuning and Scalability"},{"type":"text","content":"After pre-training, the decoder is discarded and only the encoder is fine-tuned on downstream tasks. MAE achieves 87.8% top-1 on ImageNet with ViT-H, surpassing supervised pre-training baselines. Crucially, larger ViT models benefit more from MAE pre-training — ViT-L and ViT-H show larger relative gains than ViT-B, suggesting MAE is especially well-suited to large-scale self-supervised learning."},{"type":"text","content":"In data-limited fine-tuning regimes with only 1% of ImageNet labels (~12,800 images), MAE pre-trained ViT-L achieves ~73% top-1 accuracy, dramatically outperforming training from scratch. This confirms that MAE learns genuine visual semantics rather than dataset-specific shortcuts, making it a powerful foundation for transfer learning."}]"
---
# MAE — Masked Autoencoders for Vision

Masked Autoencoders (MAE) by He et al. (2022) demonstrated that a surprisingly simple idea — mask most of an image and reconstruct the missing parts — scales remarkably well for visual pre-training. By masking 75% of patches and using an asymmetric encoder-decoder, MAE achieves strong representations without contrastive pairs, negative samples, or momentum networks.

## What is MAE?

MAE is a self-supervised pre-training method for vision transformers (ViT). The core idea mirrors BERT in NLP: randomly mask a subset of input tokens (patches) and train the model to reconstruct the originals. The key insight is that vision data is far more redundant than language — a high masking ratio (75% vs BERT's 15%) forces the model to learn holistic scene understanding rather than interpolating from nearby visible pixels.

## Patch Masking Strategy

MAE divides the input image into non-overlapping patches (typically 16x16 pixels). A random 75% of patches are masked. Crucially, the encoder sees only the remaining 25% — mask tokens are never passed to the encoder. This asymmetric design is the key efficiency win: the encoder processes only a quarter of the patches, yielding a 3–4x speedup over processing all patches.

```python
import torch
import torch.nn as nn

def random_masking(x, mask_ratio=0.75):
    # x: [B, N, D] patch embeddings
    # Returns: visible tokens, binary mask (1=masked), restore indices
    B, N, D = x.shape
    keep = int(N * (1 - mask_ratio))  # number of patches to keep

    # Generate per-sample random noise for independent shuffling
    noise = torch.rand(B, N, device=x.device)

    # Sort patches by noise to get a random permutation
    ids_shuffle = torch.argsort(noise, dim=1)        # ascending
    ids_restore = torch.argsort(ids_shuffle, dim=1)  # inverse permutation

    # Keep only the first `keep` patches (lowest noise values)
    ids_keep = ids_shuffle[:, :keep]
    x_visible = torch.gather(
        x, dim=1,
        index=ids_keep.unsqueeze(-1).expand(-1, -1, D)
    )

    # Binary mask: 0 = kept, 1 = masked (aligned with ids_restore order)
    mask = torch.ones(B, N, device=x.device)
    mask[:, :keep] = 0
    mask = torch.gather(mask, dim=1, index=ids_restore)

    return x_visible, mask, ids_restore

# Example usage: 196 patches (14x14 grid for 224px image with 16px patches)
# x = torch.randn(8, 196, 768)  # batch of 8, 196 patches, 768-dim
# x_vis, mask, ids_restore = random_masking(x, mask_ratio=0.75)
# x_vis.shape  -> [8, 49, 768]  (only 25% visible)
```

## The MAE Encoder

The encoder is a standard ViT (e.g., ViT-L with 24 blocks and 1024-dim embeddings) that operates exclusively on visible patches. Positional embeddings are added before masking so the encoder knows spatial positions. No mask tokens enter the encoder — this is what makes it computationally efficient. The encoder produces rich representations for only the visible 25% of patches.

```python
import torch
import torch.nn as nn
from einops import rearrange

class TransformerBlock(nn.Module):
    def __init__(self, dim, heads, mlp_ratio=4.0):
        super().__init__()
        self.norm1 = nn.LayerNorm(dim)
        self.attn = nn.MultiheadAttention(dim, heads, batch_first=True)
        self.norm2 = nn.LayerNorm(dim)
        self.mlp = nn.Sequential(
            nn.Linear(dim, int(dim * mlp_ratio)), nn.GELU(),
            nn.Linear(int(dim * mlp_ratio), dim)
        )
    def forward(self, x):
        x = x + self.attn(self.norm1(x), self.norm1(x), self.norm1(x))[0]
        return x + self.mlp(self.norm2(x))

class MAEEncoder(nn.Module):
    def __init__(self, img_size=224, patch_size=16, embed_dim=768, depth=12, num_heads=12):
        super().__init__()
        self.patch_embed = nn.Conv2d(3, embed_dim, patch_size, stride=patch_size)
        num_patches = (img_size // patch_size) ** 2
        self.pos_embed = nn.Parameter(torch.zeros(1, num_patches + 1, embed_dim))
        self.cls_token  = nn.Parameter(torch.zeros(1, 1, embed_dim))
        self.blocks = nn.ModuleList([TransformerBlock(embed_dim, num_heads) for _ in range(depth)])
        self.norm = nn.LayerNorm(embed_dim)

    def forward(self, x, ids_keep):
        B = x.shape[0]
        x = rearrange(self.patch_embed(x), 'b d h w -> b (h w) d')
        x = x + self.pos_embed[:, 1:, :]                                  # spatial pos-embed
        D = x.shape[-1]
        x = torch.gather(x, 1, ids_keep.unsqueeze(-1).expand(-1, -1, D)) # keep visible only
        cls = self.cls_token.expand(B, -1, -1)
        x = torch.cat([cls, x], dim=1)
        for block in self.blocks:
            x = block(x)
        return self.norm(x)  # [B, 1+keep, D]
```

## The MAE Decoder

The decoder is intentionally lightweight — only 4 transformer blocks (vs 12+ in the encoder) and a smaller embedding dimension (512 vs 768). It receives encoded visible tokens plus learnable mask tokens inserted at masked positions. Positional embeddings are added so the decoder knows which patches to reconstruct. The output head projects to pixel values for each patch.

```python
import torch
import torch.nn as nn

class MAEDecoder(nn.Module):
    def __init__(self, num_patches=196, encoder_dim=768, decoder_dim=512,
                 depth=4, num_heads=8, patch_size=16):
        super().__init__()
        self.decoder_embed = nn.Linear(encoder_dim, decoder_dim)
        self.mask_token = nn.Parameter(torch.zeros(1, 1, decoder_dim))
        self.pos_embed  = nn.Parameter(torch.zeros(1, num_patches + 1, decoder_dim))
        self.blocks = nn.ModuleList([TransformerBlock(decoder_dim, num_heads) for _ in range(depth)])
        self.norm = nn.LayerNorm(decoder_dim)
        self.pred = nn.Linear(decoder_dim, patch_size * patch_size * 3)

    def forward(self, x_encoded, ids_restore):
        x = self.decoder_embed(x_encoded)   # project encoder dim -> decoder dim
        x_vis = x[:, 1:, :]                 # strip cls token
        B, n_vis, D = x_vis.shape
        n_mask = ids_restore.shape[1] - n_vis

        # Expand mask tokens to fill masked positions
        mask_tokens = self.mask_token.expand(B, n_mask, -1)
        x_full = torch.cat([x_vis, mask_tokens], dim=1)   # [B, N, D]

        # Unshuffle: restore original patch order using inverse permutation
        x_full = torch.gather(
            x_full, 1, ids_restore.unsqueeze(-1).expand(-1, -1, D)
        )
        # Add positional embedding (full sequence) and prepend cls token
        x_full = x_full + self.pos_embed[:, 1:, :]
        x = torch.cat([x[:, :1, :], x_full], dim=1)
        for block in self.blocks:
            x = block(x)
        x = self.norm(x)
        return self.pred(x[:, 1:, :])   # [B, N, patch_size^2 * 3]
```

## Reconstruction Target

Rather than raw pixel values, MAE normalizes each patch's pixels to zero mean and unit variance before computing the loss. This per-patch normalization improves training stability and final representation quality. The loss is only computed on masked patches — visible patches are ignored. At inference time, predictions can be unnormalized back to RGB for visualization.

```python
import torch
import numpy as np
import matplotlib.pyplot as plt

def patchify(imgs, patch_size=16):
    # Convert [B, 3, H, W] images to [B, N, patch_size^2 * 3] patch tokens
    p = patch_size
    h = w = imgs.shape[-1] // p
    x = imgs.reshape(imgs.shape[0], 3, h, p, w, p)
    x = torch.einsum('nchpwq->nhwpqc', x)
    return x.reshape(imgs.shape[0], h * w, p * p * 3)

def compute_reconstruction_target(imgs, patch_size=16):
    # Per-patch mean/std normalization — the MAE reconstruction target
    target = patchify(imgs, patch_size)
    mean = target.mean(dim=-1, keepdim=True)
    std  = target.var(dim=-1, keepdim=True).sqrt().clamp(min=1e-6)
    return (target - mean) / std

def unnormalize_for_viz(pred, orig_imgs, patch_size=16):
    # Reverse patch normalization for visualization
    target = patchify(orig_imgs, patch_size)
    mean = target.mean(dim=-1, keepdim=True)
    std  = target.var(dim=-1, keepdim=True).sqrt().clamp(min=1e-6)
    return pred * std + mean

def mae_loss(pred, imgs, mask, patch_size=16):
    # MSE loss computed only on masked patches
    target = compute_reconstruction_target(imgs, patch_size)  # [B, N, p^2*3]
    loss = ((pred - target) ** 2).mean(dim=-1)               # [B, N] per-patch
    return (loss * mask).sum() / mask.sum()                   # mean over masked
```

> **Why 75% and Not 15%?**: BERT masks only 15% of tokens because language is information-dense — removing more destroys most context. Images are far more spatially redundant: adjacent pixels are highly correlated, so low mask ratios allow trivial texture interpolation. The 75% ratio forces the model to reason globally about object structure, yielding semantically richer features. Ablations show performance drops sharply at mask ratios below 60%.

## High Mask Ratio and Why It Works

The high mask ratio is simultaneously the efficiency mechanism and the representation-quality mechanism. With only 25% of patches visible, the encoder cannot rely on nearby pixel interpolation — it must learn object-level semantics. Ablations in the original paper confirm that performance degrades significantly at lower mask ratios (40–50%), validating that task difficulty drives representation quality.

- 75% mask ratio: encoder processes 3–4x fewer tokens, giving a significant training speedup
- High masking forces holistic understanding of shape, texture, and object structure
- No mask tokens in the encoder prevents exploitation of trivial local correlations
- Lightweight decoder (4 blocks) can reconstruct from strong encoder representations
- Normalized pixel targets (per-patch mean/std) improve training stability vs raw RGB

## Comparison with Related Methods

MAE sits in a family of masked image modeling (MIM) approaches that differ in reconstruction targets, masking strategies, and architectures. SimMIM uses a similar pixel-prediction target but passes all tokens (including mask tokens) to the encoder. BEiT predicts discrete visual tokens from a pretrained tokenizer. MaskFeat predicts HOG (Histograms of Oriented Gradients) features, a hand-crafted descriptor.

| Method | Mask Ratio | Reconstruction Target | Encoder Input | IN-1K Fine-tune Top-1 |
| --- | --- | --- | --- | --- |
| MAE | 75% | Normalized pixel values | Visible patches only | 87.8% (ViT-H) |
| SimMIM | 60% | Raw pixel values | All patches + mask tokens | 84.0% (SwinV2-H) |
| BEiT | 40% | Discrete visual tokens (dVAE) | All patches + mask tokens | 86.3% (ViT-L) |
| MaskFeat | 40% | HOG features | All patches + mask tokens | 84.0% (ViT-L) |

## Fine-tuning and Scalability

After pre-training, the decoder is discarded and only the encoder is fine-tuned on downstream tasks. MAE achieves 87.8% top-1 on ImageNet with ViT-H, surpassing supervised pre-training baselines. Crucially, larger ViT models benefit more from MAE pre-training — ViT-L and ViT-H show larger relative gains than ViT-B, suggesting MAE is especially well-suited to large-scale self-supervised learning.

In data-limited fine-tuning regimes with only 1% of ImageNet labels (~12,800 images), MAE pre-trained ViT-L achieves ~73% top-1 accuracy, dramatically outperforming training from scratch. This confirms that MAE learns genuine visual semantics rather than dataset-specific shortcuts, making it a powerful foundation for transfer learning.

