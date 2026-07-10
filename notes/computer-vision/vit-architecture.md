---
title: "Vision Transformer (ViT): Patch Embeddings and Global Attention"
slug: "vit-architecture"
description: "ViT applies a standard Transformer encoder to sequences of image patches — no convolutions, just patch embeddings, positional encodings, and multi-head self-attention for image classification."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Vision Transformer (ViT), introduced by Dosovitskiy et al. in 2020, applies a standard Transformer encoder — originally designed for NLP — directly to image classification. ViT divides an input image into fixed-size patches, linearly embeds each patch, and processes the resulting sequence with multi-head self-attention, achieving state-of-the-art results when pretrained at scale."},{"type":"text","content":"The key insight is that image patches can be treated like word tokens in NLP. For a 224×224 image with patch size P=16, we get N=(224/16)²=196 patches. Each patch is flattened and projected to a D-dimensional embedding, then passed through L identical Transformer encoder blocks, with a learnable [CLS] token prepended to produce the final image representation."},{"type":"heading","level":2,"content":"Patch Embedding and Tokenization"},{"type":"text","content":"Patch embedding converts a 2D image (H×W×C) into a 1D sequence of N patch tokens. A single nn.Conv2d with kernel_size=patch_size and stride=patch_size achieves this efficiently — it extracts non-overlapping patches and projects each to dimension D in one operation. The resulting tensor shape is (B, N, D) where N=HW/P² is the number of tokens per image."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass PatchEmbed(nn.Module):\n    def __init__(self, img_size=224, patch_size=16, in_ch=3, dim=768):\n        super().__init__()\n        self.n_patches = (img_size // patch_size) ** 2\n        self.proj = nn.Conv2d(in_ch, dim, kernel_size=patch_size, stride=patch_size)\n\n    def forward(self, x):\n        # x: (B, C, H, W) -\u003e (B, D, H/P, W/P) -\u003e (B, N, D)\n        x = self.proj(x)           # (B, dim, H/P, W/P)\n        x = x.flatten(2)           # (B, dim, N)\n        return x.transpose(1, 2)   # (B, N, dim)"},{"type":"text","content":"Positional embeddings are added to patch tokens so the model can reason about spatial structure. ViT uses 1D learnable positional encodings — a parameter of shape (1, N+1, D) added element-wise to the full token sequence. Despite ignoring 2D structure, 1D positional encodings work well in practice; 2D-aware variants like CPVT offer only marginal improvements on standard benchmarks."},{"type":"heading","level":2,"content":"Multi-Head Self-Attention"},{"type":"text","content":"Self-attention lets every patch token attend to all other patch tokens simultaneously, giving ViT a global receptive field from layer one. This contrasts with CNNs, which build global context gradually through stacked local convolutions. In ViT, even the first attention layer can directly relate a patch from the top-left corner of the image to one from the bottom-right corner."},{"type":"code","language":"python","content":"import math\n\ndef multihead_attention(x, W_qkv, W_o, n_heads):\n    B, N, D = x.shape\n    d_k = D // n_heads\n    qkv = x @ W_qkv                                    # (B, N, 3D)\n    q, k, v = qkv.chunk(3, dim=-1)                    # each (B, N, D)\n    reshape = lambda t: t.view(B, N, n_heads, d_k).transpose(1, 2)\n    q, k, v = reshape(q), reshape(k), reshape(v)      # (B, h, N, d_k)\n    attn = (q @ k.transpose(-2, -1)) / math.sqrt(d_k)\n    attn = attn.softmax(dim=-1)\n    out = (attn @ v).transpose(1, 2).reshape(B, N, D)\n    return out @ W_o"},{"type":"text","content":"Attention complexity scales as O(N²D), making ViT quadratic in the number of patches. For ViT-B/16 on 224×224 images this means 196² ≈ 38K attention pairs per head — manageable. At higher resolutions (512×512, N=1024) memory becomes a bottleneck. Efficient variants like Swin Transformer address this with local window attention, reducing overall complexity from O(N²) to O(N)."},{"type":"heading","level":2,"content":"Transformer Encoder Blocks"},{"type":"text","content":"Each Transformer encoder block applies two sub-layers with residual connections: (1) Layer Norm followed by Multi-Head Self-Attention, and (2) Layer Norm followed by an MLP with two linear layers and GELU activation. ViT uses pre-norm (LayerNorm before each sub-layer), which stabilizes training and allows deeper networks versus post-norm used in the original Transformer."},{"type":"code","language":"python","content":"class ViT(nn.Module):\n    def forward(self, img):\n        # 1. Patch embedding: (B,C,H,W) -\u003e (B,N,D)\n        tokens = self.patch_embed(img)\n        # 2. Prepend CLS token and add positional encoding\n        cls = self.cls_token.expand(img.size(0), -1, -1)  # (B,1,D)\n        tokens = torch.cat([cls, tokens], dim=1)           # (B,N+1,D)\n        tokens = tokens + self.pos_embed\n        tokens = self.pos_drop(tokens)\n        # 3. Pass through L encoder blocks\n        for block in self.blocks:\n            tokens = block(tokens)\n        # 4. Classify from CLS token output\n        return self.head(self.norm(tokens[:, 0]))          # (B, C)"},{"type":"table","headers":["Variant","Patch Size","Layers","Heads","Dim","Params (M)","IN-1K Top-1 %"],"rows":[["ViT-Ti","16","12","3","192","5.7","72.2"],["ViT-S","16","12","6","384","22.1","79.8"],["ViT-B","16","12","12","768","86.6","81.8"],["ViT-L","16","24","16","1024","307","85.2"],["ViT-H","14","32","16","1280","632","88.5"]]},{"type":"text","content":"The MLP inside each encoder block uses hidden dimension 4×D (e.g. 3072 for ViT-B/16 with D=768) and GELU activation. Dropout follows both attention and MLP sub-layers. Block count varies by variant: ViT-Ti and ViT-S use 12 blocks, ViT-L uses 24, ViT-H uses 32. Deeper and wider models require large-scale pretraining to leverage their additional representational capacity effectively."},{"type":"heading","level":2,"content":"CLS Token and Classification"},{"type":"text","content":"A learnable [CLS] token is prepended to the patch sequence before the first encoder block. After L Transformer blocks, the output at position 0 — corresponding to the [CLS] token — aggregates global information from all patches through self-attention and serves as the image representation. A linear classification head then maps this D-dimensional vector to the number of target output classes."},{"type":"callout","calloutType":"warning","content":"ViT requires large-scale pretraining to match CNN accuracy — ViT-B/16 trained from scratch on ImageNet-1K underperforms ResNet-50. It only surpasses CNNs with JFT-300M or 21K pretraining. Use DeiT or pretrained checkpoints for small-data fine-tuning."},{"type":"text","content":"During fine-tuning, the classification head is replaced with a fresh linear layer for the target class count, and positional embeddings are interpolated when the fine-tuning resolution differs from pretraining. ViT-B/16 pretrained on ImageNet-21K achieves 85%+ top-1 on ImageNet-1K, far exceeding the 77% obtained when training from scratch on ImageNet-1K alone."},{"type":"code","language":"python","content":"import torch, time, timm\nfrom torchvision.models import vit_b_16, resnet50\n\ndef benchmark(model, name, x):\n    model.eval()\n    n = sum(p.numel() for p in model.parameters()) / 1e6\n    with torch.no_grad():\n        for _ in range(10): model(x)   # warmup\n        t0 = time.time()\n        for _ in range(100): model(x)\n    print(f\u0027{name}: {n:.1f}M params | {100/(time.time()-t0):.1f} img/s\u0027)\n\nx = torch.randn(32, 3, 224, 224)\nbenchmark(vit_b_16(weights=\u0027DEFAULT\u0027), \u0027ViT-B/16\u0027, x)\nbenchmark(resnet50(weights=\u0027DEFAULT\u0027), \u0027ResNet-50\u0027, x)"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"ViT replaces CNN inductive biases — translation equivariance and locality — with raw self-attention over patch tokens. This makes ViT more general but data-hungry. Trained on JFT-300M (300 million images), ViT-H achieves 88.5% top-1 on ImageNet, surpassing all CNNs of comparable parameter count and establishing Transformers as first-class image classification models."},{"type":"text","content":"Patch size is the primary resolution-accuracy trade-off in ViT. Smaller patches (P=14 in ViT-H) yield more tokens and finer spatial detail but increase attention compute quadratically. Larger patches (P=32) train faster and suit high-throughput inference but miss fine-grained textures. P=16 balances accuracy and speed for classification; dense prediction tasks typically use smaller patches."},{"type":"text","content":"ViT\u0027s architecture enabled key successors: DeiT adds knowledge distillation for small-data training, Swin Transformer introduces hierarchical windowed attention for dense prediction, BEiT and MAE apply masked autoencoders for self-supervised pretraining, and CLIP pairs ViT with contrastive language-image pretraining. ViT is now the dominant backbone for large-scale vision and multimodal models."}]"
---
# Vision Transformer (ViT): Patch Embeddings and Global Attention

## Overview

Vision Transformer (ViT), introduced by Dosovitskiy et al. in 2020, applies a standard Transformer encoder — originally designed for NLP — directly to image classification. ViT divides an input image into fixed-size patches, linearly embeds each patch, and processes the resulting sequence with multi-head self-attention, achieving state-of-the-art results when pretrained at scale.

The key insight is that image patches can be treated like word tokens in NLP. For a 224×224 image with patch size P=16, we get N=(224/16)²=196 patches. Each patch is flattened and projected to a D-dimensional embedding, then passed through L identical Transformer encoder blocks, with a learnable [CLS] token prepended to produce the final image representation.

## Patch Embedding and Tokenization

Patch embedding converts a 2D image (H×W×C) into a 1D sequence of N patch tokens. A single nn.Conv2d with kernel_size=patch_size and stride=patch_size achieves this efficiently — it extracts non-overlapping patches and projects each to dimension D in one operation. The resulting tensor shape is (B, N, D) where N=HW/P² is the number of tokens per image.

```python
import torch
import torch.nn as nn

class PatchEmbed(nn.Module):
    def __init__(self, img_size=224, patch_size=16, in_ch=3, dim=768):
        super().__init__()
        self.n_patches = (img_size // patch_size) ** 2
        self.proj = nn.Conv2d(in_ch, dim, kernel_size=patch_size, stride=patch_size)

    def forward(self, x):
        # x: (B, C, H, W) -> (B, D, H/P, W/P) -> (B, N, D)
        x = self.proj(x)           # (B, dim, H/P, W/P)
        x = x.flatten(2)           # (B, dim, N)
        return x.transpose(1, 2)   # (B, N, dim)
```

Positional embeddings are added to patch tokens so the model can reason about spatial structure. ViT uses 1D learnable positional encodings — a parameter of shape (1, N+1, D) added element-wise to the full token sequence. Despite ignoring 2D structure, 1D positional encodings work well in practice; 2D-aware variants like CPVT offer only marginal improvements on standard benchmarks.

## Multi-Head Self-Attention

Self-attention lets every patch token attend to all other patch tokens simultaneously, giving ViT a global receptive field from layer one. This contrasts with CNNs, which build global context gradually through stacked local convolutions. In ViT, even the first attention layer can directly relate a patch from the top-left corner of the image to one from the bottom-right corner.

```python
import math

def multihead_attention(x, W_qkv, W_o, n_heads):
    B, N, D = x.shape
    d_k = D // n_heads
    qkv = x @ W_qkv                                    # (B, N, 3D)
    q, k, v = qkv.chunk(3, dim=-1)                    # each (B, N, D)
    reshape = lambda t: t.view(B, N, n_heads, d_k).transpose(1, 2)
    q, k, v = reshape(q), reshape(k), reshape(v)      # (B, h, N, d_k)
    attn = (q @ k.transpose(-2, -1)) / math.sqrt(d_k)
    attn = attn.softmax(dim=-1)
    out = (attn @ v).transpose(1, 2).reshape(B, N, D)
    return out @ W_o
```

Attention complexity scales as O(N²D), making ViT quadratic in the number of patches. For ViT-B/16 on 224×224 images this means 196² ≈ 38K attention pairs per head — manageable. At higher resolutions (512×512, N=1024) memory becomes a bottleneck. Efficient variants like Swin Transformer address this with local window attention, reducing overall complexity from O(N²) to O(N).

## Transformer Encoder Blocks

Each Transformer encoder block applies two sub-layers with residual connections: (1) Layer Norm followed by Multi-Head Self-Attention, and (2) Layer Norm followed by an MLP with two linear layers and GELU activation. ViT uses pre-norm (LayerNorm before each sub-layer), which stabilizes training and allows deeper networks versus post-norm used in the original Transformer.

```python
class ViT(nn.Module):
    def forward(self, img):
        # 1. Patch embedding: (B,C,H,W) -> (B,N,D)
        tokens = self.patch_embed(img)
        # 2. Prepend CLS token and add positional encoding
        cls = self.cls_token.expand(img.size(0), -1, -1)  # (B,1,D)
        tokens = torch.cat([cls, tokens], dim=1)           # (B,N+1,D)
        tokens = tokens + self.pos_embed
        tokens = self.pos_drop(tokens)
        # 3. Pass through L encoder blocks
        for block in self.blocks:
            tokens = block(tokens)
        # 4. Classify from CLS token output
        return self.head(self.norm(tokens[:, 0]))          # (B, C)
```

| Variant | Patch Size | Layers | Heads | Dim | Params (M) | IN-1K Top-1 % |
| --- | --- | --- | --- | --- | --- | --- |
| ViT-Ti | 16 | 12 | 3 | 192 | 5.7 | 72.2 |
| ViT-S | 16 | 12 | 6 | 384 | 22.1 | 79.8 |
| ViT-B | 16 | 12 | 12 | 768 | 86.6 | 81.8 |
| ViT-L | 16 | 24 | 16 | 1024 | 307 | 85.2 |
| ViT-H | 14 | 32 | 16 | 1280 | 632 | 88.5 |

The MLP inside each encoder block uses hidden dimension 4×D (e.g. 3072 for ViT-B/16 with D=768) and GELU activation. Dropout follows both attention and MLP sub-layers. Block count varies by variant: ViT-Ti and ViT-S use 12 blocks, ViT-L uses 24, ViT-H uses 32. Deeper and wider models require large-scale pretraining to leverage their additional representational capacity effectively.

## CLS Token and Classification

A learnable [CLS] token is prepended to the patch sequence before the first encoder block. After L Transformer blocks, the output at position 0 — corresponding to the [CLS] token — aggregates global information from all patches through self-attention and serves as the image representation. A linear classification head then maps this D-dimensional vector to the number of target output classes.

> ****: ViT requires large-scale pretraining to match CNN accuracy — ViT-B/16 trained from scratch on ImageNet-1K underperforms ResNet-50. It only surpasses CNNs with JFT-300M or 21K pretraining. Use DeiT or pretrained checkpoints for small-data fine-tuning.

During fine-tuning, the classification head is replaced with a fresh linear layer for the target class count, and positional embeddings are interpolated when the fine-tuning resolution differs from pretraining. ViT-B/16 pretrained on ImageNet-21K achieves 85%+ top-1 on ImageNet-1K, far exceeding the 77% obtained when training from scratch on ImageNet-1K alone.

```python
import torch, time, timm
from torchvision.models import vit_b_16, resnet50

def benchmark(model, name, x):
    model.eval()
    n = sum(p.numel() for p in model.parameters()) / 1e6
    with torch.no_grad():
        for _ in range(10): model(x)   # warmup
        t0 = time.time()
        for _ in range(100): model(x)
    print(f'{name}: {n:.1f}M params | {100/(time.time()-t0):.1f} img/s')

x = torch.randn(32, 3, 224, 224)
benchmark(vit_b_16(weights='DEFAULT'), 'ViT-B/16', x)
benchmark(resnet50(weights='DEFAULT'), 'ResNet-50', x)
```

## Key Takeaways

ViT replaces CNN inductive biases — translation equivariance and locality — with raw self-attention over patch tokens. This makes ViT more general but data-hungry. Trained on JFT-300M (300 million images), ViT-H achieves 88.5% top-1 on ImageNet, surpassing all CNNs of comparable parameter count and establishing Transformers as first-class image classification models.

Patch size is the primary resolution-accuracy trade-off in ViT. Smaller patches (P=14 in ViT-H) yield more tokens and finer spatial detail but increase attention compute quadratically. Larger patches (P=32) train faster and suit high-throughput inference but miss fine-grained textures. P=16 balances accuracy and speed for classification; dense prediction tasks typically use smaller patches.

ViT's architecture enabled key successors: DeiT adds knowledge distillation for small-data training, Swin Transformer introduces hierarchical windowed attention for dense prediction, BEiT and MAE apply masked autoencoders for self-supervised pretraining, and CLIP pairs ViT with contrastive language-image pretraining. ViT is now the dominant backbone for large-scale vision and multimodal models.

