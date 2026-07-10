---
title: "Efficient ViT: Token Merging and Reduction Strategies"
slug: "efficient-vit-token-merging"
description: "A practical guide to token merging, pruning, and pooling strategies that cut ViT inference cost by 1.5–3× with minimal accuracy loss."
tags: ["vision-transformer", "efficiency", "token-merging", "pruning", "inference"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Standard ViTs scale quadratically with token count: a 224px image at patch size 16 produces 196 tokens, but at 512px that becomes 1024 tokens and attention cost grows 27×. Token reduction strategies — merging, pruning, or pooling — break this bottleneck by reducing effective sequence length while preserving most information content for downstream tasks."},{"type":"text","content":"The core observation motivating token reduction is that image patches are highly redundant. In natural images, adjacent patches share color, texture, and semantic content. A model processing a uniform sky region computes nearly identical attention patterns across dozens of tokens. Identifying and collapsing these redundant tokens is the central challenge of efficient ViT design."},{"type":"callout","variant":"tip","title":"Tip","content":"ToMe requires zero retraining — plug it into any pretrained ViT by wrapping the attention module. Start at r=8 for ~1.5x speedup with \u003c0.3% accuracy drop."},{"type":"heading","level":2,"content":"Token Redundancy in Attention"},{"type":"text","content":"Attention maps in early ViT layers show strong spatial locality: most tokens attend primarily to immediate neighbors. In later layers, global semantics emerge but many tokens still carry nearly identical key-query representations. Measuring pairwise cosine similarity between token features reveals that 30–50% of tokens have at least one near-duplicate (sim \u003e 0.9) in typical ImageNet images."},{"type":"code","language":"python","content":"# Compute token similarity matrix; threshold at tau to find mergeable pairs\nimport torch\n\ndef token_similarity(x, tau=0.9):\n    # x: (B, N, D) token features\n    d = x.shape[-1]\n    x_norm = x / x.norm(dim=-1, keepdim=True)\n    sim = (x_norm @ x_norm.transpose(-1, -2)) / (d ** 0.5)  # (B, N, N)\n    mask = torch.eye(sim.shape[-1], device=x.device).bool()\n    sim = sim.masked_fill(mask.unsqueeze(0), -1.0)\n    mergeable = (sim \u003e tau).any(dim=-1)   # (B, N) boolean mask\n    redundancy = mergeable.float().mean()\n    return sim, redundancy\n\nsim_mat, red = token_similarity(patch_tokens)\nprint(f\u0027Token redundancy: {red:.1%}\u0027)"},{"type":"text","content":"Redundancy is not uniformly distributed across layers. Early blocks show high spatial redundancy (adjacent patches); middle blocks show semantic redundancy (same-object patches); final blocks are most diverse since each token has accumulated global context. This profile motivates applying more aggressive reduction in early layers and preserving more tokens in later layers."},{"type":"heading","level":2,"content":"Token Merging (ToMe)"},{"type":"text","content":"Token Merging (ToMe) by Bolya et al. 2023 introduces a training-free method to reduce ViT token count at inference. At each transformer block, it partitions tokens into two sets — source (src) and destination (dst) — using bipartite matching. The top-r most similar src-dst pairs are merged by averaging their features, reducing the sequence by r tokens per block."},{"type":"code","language":"python","content":"# ToMe bipartite matching: merge top-r src tokens into nearest dst tokens\nimport torch\n\ndef tome_merge(x, r):\n    # x: (B, N, D); r: tokens to merge per block\n    B, N, D = x.shape\n    src = x[:, 1::2, :]   # odd-indexed tokens\n    dst = x[:, 0::2, :]   # even-indexed tokens\n    src_n = src / src.norm(dim=-1, keepdim=True)\n    dst_n = dst / dst.norm(dim=-1, keepdim=True)\n    sim = src_n @ dst_n.transpose(-1, -2)   # (B, N//2, N//2)\n    scores, best_dst = sim.max(dim=-1)      # per-src best dst\n    _, top_r_idx = scores.topk(r, dim=-1)  # top-r src by similarity\n    for b in range(B):\n        for i in range(r):\n            s_i = top_r_idx[b, i]\n            d_i = best_dst[b, s_i]\n            dst[b, d_i] = (dst[b, d_i] + src[b, s_i]) / 2\n    return dst"},{"type":"text","content":"ToMe operates inside the attention module before the softmax, so merged tokens reduce both the QK^T matrix size and feedforward computation in the same block. No gradient flows through the merge operation at inference, but during training-aware ToMe, a straight-through estimator allows the merge schedule to be learned jointly with the network weights."},{"type":"heading","level":2,"content":"Token Pruning and Pooling"},{"type":"text","content":"Token pruning takes a harder decision than merging: tokens below a relevance threshold are dropped entirely rather than averaged into neighbors. DynamicViT predicts per-token importance scores with a lightweight 2-layer MLP, then uses Gumbel-softmax to make the drop decision differentiable during training. At inference the Gumbel noise is removed and scores are thresholded deterministically."},{"type":"code","language":"python","content":"# DynamicViT: predict token keep scores with MLP, Gumbel-softmax drop\nimport torch, torch.nn as nn, torch.nn.functional as F\n\nclass TokenPredictor(nn.Module):\n    def __init__(self, dim):\n        super().__init__()\n        self.score = nn.Sequential(\n            nn.Linear(dim, dim // 4), nn.GELU(), nn.Linear(dim // 4, 2))\n\n    def forward(self, x, keep_ratio=0.7, training=True):\n        logits = self.score(x)            # (B, N, 2): [drop, keep]\n        if training:\n            decisions = F.gumbel_softmax(logits, tau=1.0, hard=True)\n            keep_mask = decisions[..., 1]\n        else:\n            scores = logits.softmax(-1)[..., 1]\n            topk = int(x.shape[1] * keep_ratio)\n            _, idx = scores.topk(topk, dim=-1)\n            keep_mask = torch.zeros_like(scores).scatter_(-1, idx, 1.0)\n        return x * keep_mask.unsqueeze(-1), keep_mask"},{"type":"text","content":"Spatial pooling is the simplest reduction: apply average pooling over 2×2 windows of patch tokens, reducing the sequence by 4× per pooling stage. This is the approach used in PVT and Twins. Unlike merging or pruning, pooling is content-agnostic — it always reduces by a fixed factor regardless of image content — but it composes naturally with convolution and requires no learned selection mechanism."},{"type":"heading","level":2,"content":"Speed-Accuracy Tradeoffs"},{"type":"text","content":"Benchmarking token reduction requires measuring throughput at a fixed batch size and resolution, not just FLOPs. Wall-clock speedup often deviates from FLOP reduction because token reduction introduces irregular computation patterns that GPUs handle less efficiently than uniform matmul operations. ToMe at r=8 reduces FLOPs by ~30% but achieves only ~1.5× wall-clock speedup due to overhead from the merge bookkeeping."},{"type":"code","language":"python","content":"# Benchmark throughput at varying r merge budgets\nimport torch, time\n\ndef benchmark(model, r_values=[0, 8, 16, 24], batch=32, runs=100):\n    x = torch.randn(batch, 3, 224, 224).cuda()\n    results = []\n    for r in r_values:\n        model.set_tome_r(r)     # sets merge budget per block\n        for _ in range(10):     # warmup\n            with torch.no_grad(): model(x)\n        torch.cuda.synchronize()\n        t0 = time.perf_counter()\n        for _ in range(runs):\n            with torch.no_grad(): model(x)\n        torch.cuda.synchronize()\n        imgs_per_sec = (batch * runs) / (time.perf_counter() - t0)\n        results.append({\u0027r\u0027: r, \u0027imgs_per_sec\u0027: imgs_per_sec})\n    return results"},{"type":"table","headers":["Method","Reduction","Throughput Gain","Top-1 Drop","Compatible With"],"rows":[["ToMe r=8","~15%","1.5x","\u003c0.3%","Any pretrained ViT"],["ToMe r=16","~30%","1.9x","0.5%","Any pretrained ViT"],["DynamicViT 30%","30%","1.6x","0.4%","Requires retraining"],["EViT 30%","30%","1.7x","0.5%","Requires retraining"],["Pooling 2x2","75%","2.8x","1.5%","Architecture-specific"]]},{"type":"text","content":"For production, ToMe at r=8 is the pragmatic default: zero retraining, drop-in compatibility, safe accuracy tradeoff. If training from scratch, DynamicViT or EViT provide better per-layer reduction control. Pooling is best when the task is classification-only and spatial resolution is not needed beyond the first few blocks of the transformer stack."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Token reduction is now a standard tool in the efficient ViT toolkit. The design space has three axes: when to reduce (which layers), how much to reduce (ratio or fixed count), and how to reduce (merge, prune, or pool). Best results combine modest reduction in early layers with more aggressive reduction in mid-layers, leaving late layers at full token count to preserve global representations."},{"type":"text","content":"The training-free vs training-aware split is a practical decision. Training-free methods like ToMe work immediately on any checkpoint and are essential when you cannot afford to retrain. Training-aware methods recover accuracy at higher reduction rates but require rerunning the training pipeline. For most teams, training-free methods will capture 80% of the speedup benefit at zero additional training cost."},{"type":"text","content":"Token reduction does not change the ViT architecture — it changes the input sequence to each block. This means reduced models retain full compatibility with the original attention mechanism, positional embeddings, and layer normalization. The reduction can be applied, tuned, or removed at inference time without any weight modification, making it a true inference-time hyperparameter."}]"
---
# Efficient ViT: Token Merging and Reduction Strategies

## Overview

Standard ViTs scale quadratically with token count: a 224px image at patch size 16 produces 196 tokens, but at 512px that becomes 1024 tokens and attention cost grows 27×. Token reduction strategies — merging, pruning, or pooling — break this bottleneck by reducing effective sequence length while preserving most information content for downstream tasks.

The core observation motivating token reduction is that image patches are highly redundant. In natural images, adjacent patches share color, texture, and semantic content. A model processing a uniform sky region computes nearly identical attention patterns across dozens of tokens. Identifying and collapsing these redundant tokens is the central challenge of efficient ViT design.

> **Tip**: ToMe requires zero retraining — plug it into any pretrained ViT by wrapping the attention module. Start at r=8 for ~1.5x speedup with <0.3% accuracy drop.

## Token Redundancy in Attention

Attention maps in early ViT layers show strong spatial locality: most tokens attend primarily to immediate neighbors. In later layers, global semantics emerge but many tokens still carry nearly identical key-query representations. Measuring pairwise cosine similarity between token features reveals that 30–50% of tokens have at least one near-duplicate (sim > 0.9) in typical ImageNet images.

```python
# Compute token similarity matrix; threshold at tau to find mergeable pairs
import torch

def token_similarity(x, tau=0.9):
    # x: (B, N, D) token features
    d = x.shape[-1]
    x_norm = x / x.norm(dim=-1, keepdim=True)
    sim = (x_norm @ x_norm.transpose(-1, -2)) / (d ** 0.5)  # (B, N, N)
    mask = torch.eye(sim.shape[-1], device=x.device).bool()
    sim = sim.masked_fill(mask.unsqueeze(0), -1.0)
    mergeable = (sim > tau).any(dim=-1)   # (B, N) boolean mask
    redundancy = mergeable.float().mean()
    return sim, redundancy

sim_mat, red = token_similarity(patch_tokens)
print(f'Token redundancy: {red:.1%}')
```

Redundancy is not uniformly distributed across layers. Early blocks show high spatial redundancy (adjacent patches); middle blocks show semantic redundancy (same-object patches); final blocks are most diverse since each token has accumulated global context. This profile motivates applying more aggressive reduction in early layers and preserving more tokens in later layers.

## Token Merging (ToMe)

Token Merging (ToMe) by Bolya et al. 2023 introduces a training-free method to reduce ViT token count at inference. At each transformer block, it partitions tokens into two sets — source (src) and destination (dst) — using bipartite matching. The top-r most similar src-dst pairs are merged by averaging their features, reducing the sequence by r tokens per block.

```python
# ToMe bipartite matching: merge top-r src tokens into nearest dst tokens
import torch

def tome_merge(x, r):
    # x: (B, N, D); r: tokens to merge per block
    B, N, D = x.shape
    src = x[:, 1::2, :]   # odd-indexed tokens
    dst = x[:, 0::2, :]   # even-indexed tokens
    src_n = src / src.norm(dim=-1, keepdim=True)
    dst_n = dst / dst.norm(dim=-1, keepdim=True)
    sim = src_n @ dst_n.transpose(-1, -2)   # (B, N//2, N//2)
    scores, best_dst = sim.max(dim=-1)      # per-src best dst
    _, top_r_idx = scores.topk(r, dim=-1)  # top-r src by similarity
    for b in range(B):
        for i in range(r):
            s_i = top_r_idx[b, i]
            d_i = best_dst[b, s_i]
            dst[b, d_i] = (dst[b, d_i] + src[b, s_i]) / 2
    return dst
```

ToMe operates inside the attention module before the softmax, so merged tokens reduce both the QK^T matrix size and feedforward computation in the same block. No gradient flows through the merge operation at inference, but during training-aware ToMe, a straight-through estimator allows the merge schedule to be learned jointly with the network weights.

## Token Pruning and Pooling

Token pruning takes a harder decision than merging: tokens below a relevance threshold are dropped entirely rather than averaged into neighbors. DynamicViT predicts per-token importance scores with a lightweight 2-layer MLP, then uses Gumbel-softmax to make the drop decision differentiable during training. At inference the Gumbel noise is removed and scores are thresholded deterministically.

```python
# DynamicViT: predict token keep scores with MLP, Gumbel-softmax drop
import torch, torch.nn as nn, torch.nn.functional as F

class TokenPredictor(nn.Module):
    def __init__(self, dim):
        super().__init__()
        self.score = nn.Sequential(
            nn.Linear(dim, dim // 4), nn.GELU(), nn.Linear(dim // 4, 2))

    def forward(self, x, keep_ratio=0.7, training=True):
        logits = self.score(x)            # (B, N, 2): [drop, keep]
        if training:
            decisions = F.gumbel_softmax(logits, tau=1.0, hard=True)
            keep_mask = decisions[..., 1]
        else:
            scores = logits.softmax(-1)[..., 1]
            topk = int(x.shape[1] * keep_ratio)
            _, idx = scores.topk(topk, dim=-1)
            keep_mask = torch.zeros_like(scores).scatter_(-1, idx, 1.0)
        return x * keep_mask.unsqueeze(-1), keep_mask
```

Spatial pooling is the simplest reduction: apply average pooling over 2×2 windows of patch tokens, reducing the sequence by 4× per pooling stage. This is the approach used in PVT and Twins. Unlike merging or pruning, pooling is content-agnostic — it always reduces by a fixed factor regardless of image content — but it composes naturally with convolution and requires no learned selection mechanism.

## Speed-Accuracy Tradeoffs

Benchmarking token reduction requires measuring throughput at a fixed batch size and resolution, not just FLOPs. Wall-clock speedup often deviates from FLOP reduction because token reduction introduces irregular computation patterns that GPUs handle less efficiently than uniform matmul operations. ToMe at r=8 reduces FLOPs by ~30% but achieves only ~1.5× wall-clock speedup due to overhead from the merge bookkeeping.

```python
# Benchmark throughput at varying r merge budgets
import torch, time

def benchmark(model, r_values=[0, 8, 16, 24], batch=32, runs=100):
    x = torch.randn(batch, 3, 224, 224).cuda()
    results = []
    for r in r_values:
        model.set_tome_r(r)     # sets merge budget per block
        for _ in range(10):     # warmup
            with torch.no_grad(): model(x)
        torch.cuda.synchronize()
        t0 = time.perf_counter()
        for _ in range(runs):
            with torch.no_grad(): model(x)
        torch.cuda.synchronize()
        imgs_per_sec = (batch * runs) / (time.perf_counter() - t0)
        results.append({'r': r, 'imgs_per_sec': imgs_per_sec})
    return results
```

| Method | Reduction | Throughput Gain | Top-1 Drop | Compatible With |
| --- | --- | --- | --- | --- |
| ToMe r=8 | ~15% | 1.5x | <0.3% | Any pretrained ViT |
| ToMe r=16 | ~30% | 1.9x | 0.5% | Any pretrained ViT |
| DynamicViT 30% | 30% | 1.6x | 0.4% | Requires retraining |
| EViT 30% | 30% | 1.7x | 0.5% | Requires retraining |
| Pooling 2x2 | 75% | 2.8x | 1.5% | Architecture-specific |

For production, ToMe at r=8 is the pragmatic default: zero retraining, drop-in compatibility, safe accuracy tradeoff. If training from scratch, DynamicViT or EViT provide better per-layer reduction control. Pooling is best when the task is classification-only and spatial resolution is not needed beyond the first few blocks of the transformer stack.

## Key Takeaways

Token reduction is now a standard tool in the efficient ViT toolkit. The design space has three axes: when to reduce (which layers), how much to reduce (ratio or fixed count), and how to reduce (merge, prune, or pool). Best results combine modest reduction in early layers with more aggressive reduction in mid-layers, leaving late layers at full token count to preserve global representations.

The training-free vs training-aware split is a practical decision. Training-free methods like ToMe work immediately on any checkpoint and are essential when you cannot afford to retrain. Training-aware methods recover accuracy at higher reduction rates but require rerunning the training pipeline. For most teams, training-free methods will capture 80% of the speedup benefit at zero additional training cost.

Token reduction does not change the ViT architecture — it changes the input sequence to each block. This means reduced models retain full compatibility with the original attention mechanism, positional embeddings, and layer normalization. The reduction can be applied, tuned, or removed at inference time without any weight modification, making it a true inference-time hyperparameter.

