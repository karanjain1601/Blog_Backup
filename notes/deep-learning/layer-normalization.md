---
title: "Layer Normalization — Sequence Models and Pre/Post-Norm"
slug: "layer-normalization"
description: "Derive LN from first principles, contrast pre-norm vs post-norm Transformer architectures, compare BN vs LN vs RMSNorm vs GroupNorm, and analyze gradient flow across normalization methods."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Layer Normalization (Ba et al. 2016) normalizes activations across the feature dimension of each individual sample, making it batch-size independent and consistent between training and inference. Unlike Batch Normalization which normalizes across the batch dimension, LN operates on each token\u0027s feature vector in isolation — a property that makes it the standard normalization choice for Transformers, RNNs, and any architecture processing variable-length sequences."},{"type":"heading","level":2,"content":"Layer Normalization Formula"},{"type":"text","content":"For an input vector x ∈ ℝᵈ, Layer Normalization computes: μ = (1/d) Σᵢ xᵢ (mean over feature dim), σ² = (1/d) Σᵢ (xᵢ − μ)² (variance over feature dim), x̂ᵢ = (xᵢ − μ) / √(σ² + ε) (normalize), yᵢ = γᵢ x̂ᵢ + βᵢ (scale and shift). The learned parameters γ (scale) and β (shift) have the same dimension as the feature vector, giving the model freedom to undo the normalization if beneficial. ε is a small constant (typically 1e-5) for numerical stability."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\n\ndef layer_norm_numpy(x, gamma, beta, eps=1e-5):\n    # x: (..., features) — normalize over last dimension\n    mean = x.mean(axis=-1, keepdims=True)\n    var = x.var(axis=-1, keepdims=True, ddof=0)\n    x_hat = (x - mean) / np.sqrt(var + eps)\n    return gamma * x_hat + beta\n\nnp.random.seed(42)\nbatch, seq, features = 2, 10, 64\nx_np = np.random.randn(batch, seq, features).astype(np.float32)\ngamma_np = np.ones(features, dtype=np.float32)\nbeta_np = np.zeros(features, dtype=np.float32)\nout_scratch = layer_norm_numpy(x_np, gamma_np, beta_np)\n\nx_torch = torch.tensor(x_np)\nln = nn.LayerNorm(features)\nwith torch.no_grad():\n    ln.weight.fill_(1.0)\n    ln.bias.fill_(0.0)\nout_torch = ln(x_torch).detach().numpy()\n\nprint(f\u0027Max diff scratch vs PyTorch: {np.abs(out_scratch - out_torch).max():.2e}\u0027)\nprint(f\u0027Per-token mean after LN (should ~0): {out_scratch.mean(axis=-1).mean():.6f}\u0027)\nprint(f\u0027Per-token std  after LN (should ~1): {out_scratch.std(axis=-1).mean():.6f}\u0027)"},{"type":"heading","level":2,"content":"Batch Normalization vs Layer Normalization"},{"type":"text","content":"Batch Normalization normalizes across the batch dimension: for each feature j, BN computes the mean and variance over all samples in the batch. This creates three problems in sequence modeling: (1) statistics depend on batch size — noisy at small batches; (2) different computation at train (batch stats) vs eval (running stats) causing a train/eval gap; (3) variable-length sequences cannot be batched cleanly since padding tokens corrupt batch statistics. LN computes statistics per-sample over the feature dimension, eliminating all three problems."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef compare_norms(batch_size, seq_len=10, features=32):\n    x = torch.randn(batch_size, seq_len, features)\n\n    ln = nn.LayerNorm(features)\n    out_ln = ln(x)\n    ln_info = f\u0027mean={out_ln.mean():.3f}, std={out_ln.std():.3f}\u0027\n\n    bn = nn.BatchNorm1d(features)\n    x_flat = x.reshape(batch_size * seq_len, features)\n    try:\n        out_bn = bn(x_flat)\n        bn_info = f\u0027mean={out_bn.mean():.3f}, std={out_bn.std():.3f}\u0027\n    except RuntimeError as e:\n        bn_info = f\u0027ERROR: {str(e)[:60]}\u0027\n\n    print(f\u0027  batch_size={batch_size}:\u0027)\n    print(f\u0027    LayerNorm  : {ln_info}\u0027)\n    print(f\u0027    BatchNorm1d: {bn_info}\u0027)\n\nprint(\u0027=== Normalization at different batch sizes ===\u0027)\nfor bs in [8, 4, 2, 1]:\n    compare_norms(bs)\nprint(\u0027\\nLN is batch-size independent. BN degrades sharply at batch_size=1.\u0027)"},{"type":"heading","level":2,"content":"Pre-Norm and Post-Norm Transformer Architectures"},{"type":"text","content":"The original Transformer (Vaswani et al. 2017) used Post-LN: y = LN(x + Sublayer(x)). Normalization is applied after the residual addition. Pre-LN (GPT-2, LLaMA, PaLM): y = x + Sublayer(LN(x)). Normalization is applied before each sublayer; the residual stream grows without being bounded by normalization, giving more stable gradient flow. Pre-LN typically requires no learning rate warmup and trains more reliably at depth ≥ 24 layers. Post-LN can achieve marginally better final perplexity but requires careful tuning."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass PreNormBlock(nn.Module):\n    def __init__(self, d_model, nhead, dim_ff):\n        super().__init__()\n        self.attn = nn.MultiheadAttention(d_model, nhead, batch_first=True)\n        self.ff = nn.Sequential(\n            nn.Linear(d_model, dim_ff), nn.GELU(), nn.Linear(dim_ff, d_model))\n        self.ln1 = nn.LayerNorm(d_model)\n        self.ln2 = nn.LayerNorm(d_model)\n    def forward(self, x):\n        n = self.ln1(x)\n        x = x + self.attn(n, n, n)[0]\n        x = x + self.ff(self.ln2(x))\n        return x\n\nclass PostNormBlock(nn.Module):\n    def __init__(self, d_model, nhead, dim_ff):\n        super().__init__()\n        self.attn = nn.MultiheadAttention(d_model, nhead, batch_first=True)\n        self.ff = nn.Sequential(\n            nn.Linear(d_model, dim_ff), nn.GELU(), nn.Linear(dim_ff, d_model))\n        self.ln1 = nn.LayerNorm(d_model)\n        self.ln2 = nn.LayerNorm(d_model)\n    def forward(self, x):\n        x = self.ln1(x + self.attn(x, x, x)[0])\n        x = self.ln2(x + self.ff(x))\n        return x\n\nd_model, nhead, dim_ff = 64, 4, 128\nx = torch.randn(2, 16, d_model)\npre = PreNormBlock(d_model, nhead, dim_ff)\npost = PostNormBlock(d_model, nhead, dim_ff)\nprint(f\u0027PreNorm  output norm: {pre(x).norm().item():.4f}\u0027)\nprint(f\u0027PostNorm output norm: {post(x).norm().item():.4f}\u0027)\nprint(\u0027PreNorm residual grows freely; PostNorm bounded by LN at each sublayer output.\u0027)"},{"type":"callout","variant":"info","title":"Pre-Norm is the Modern Default","content":"All major LLMs — GPT-2, GPT-3, LLaMA 1/2/3, PaLM, Falcon, Mistral — use Pre-LN. Post-LN (original Transformer) can achieve slightly better final perplexity but requires careful warmup schedules and often diverges in models deeper than 24 layers. For new architectures, start with Pre-LN."},{"type":"heading","level":2,"content":"Why Layer Norm Replaced Batch Norm in Sequence Models"},{"type":"text","content":"Three properties make LN uniquely suited to sequence modeling: Batch independence — LN statistics are computed per-sample, so normalization is identical at batch_size=1 and batch_size=512. Variable-length compatibility — each token is normalized using only its own feature vector, so sequences of different lengths can be processed without any special handling. Train/eval consistency — LN uses the same formula at training and inference with no running-mean accumulation and no behavioral shift between model.train() and model.eval(). BN violates all three properties."},{"type":"list","ordered":false,"items":["Batch independence: LN computes mean/var over the feature dim of each sample — no batch coupling.","Variable sequences: padding tokens would corrupt BN batch statistics; LN processes each position independently.","No train/eval gap: BN uses batch stats at train and running stats at eval; LN behavior is identical in both modes.","Consistent gradient: LN gradient depends only on the local sample — no cross-batch gradient coupling in backward pass."]},{"type":"heading","level":2,"content":"Gradient Flow Through Layer Norm"},{"type":"text","content":"The gradient of the LN output with respect to the input has a centering component: ∂L/∂x ∝ [∂L/∂x̂ − mean(∂L/∂x̂) − x̂ · mean(∂L/∂x̂ · x̂)] / σ. The mean subtraction terms prevent constant gradient components from flowing back, acting as an implicit gradient regularizer. For BN, gradients are coupled across the batch — each sample\u0027s gradient depends on all others, which can cause instability when batch size changes between training and inference."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef measure_grad_flow(norm_class, input_shape, **kwargs):\n    x = torch.randn(*input_shape, requires_grad=True)\n    layer = norm_class(**kwargs)\n    out = layer(x)\n    loss = out.pow(2).mean()\n    loss.backward()\n    return x.grad.abs().mean().item(), x.grad.std().item()\n\nB, T, C = 4, 20, 64\nln_mean, ln_std = measure_grad_flow(nn.LayerNorm, (B, T, C), normalized_shape=C)\n\nclass BNSeq(nn.Module):\n    def __init__(self, num_features):\n        super().__init__()\n        self.bn = nn.BatchNorm1d(num_features)\n    def forward(self, x):\n        B, T, C = x.shape\n        return self.bn(x.reshape(B * T, C)).reshape(B, T, C)\n\nbn_mean, bn_std = measure_grad_flow(BNSeq, (B, T, C), num_features=C)\n\nprint(f\u0027LayerNorm grad: mean={ln_mean:.6f}, std={ln_std:.6f}\u0027)\nprint(f\u0027BatchNorm grad: mean={bn_mean:.6f}, std={bn_std:.6f}\u0027)\nprint(\u0027LN gradient is per-sample — no cross-batch coupling in the backward pass.\u0027)"},{"type":"heading","level":2,"content":"Embedding Layer Normalization"},{"type":"text","content":"Modern LLMs apply LN to the embedding outputs before feeding them into the first transformer block. This bounds the scale of the initial residual stream and prevents early layers from spending capacity on normalization. BERT and RoBERTa apply LN after summing token and positional embeddings. GPT-NeoX uses a separate embedding normalization before and after the embedding lookup. The LN parameters at the embedding layer are learned independently from the LN inside each transformer block."},{"type":"heading","level":2,"content":"Normalization Methods Comparison"},{"type":"table","headers":["Method","Normalizes Over","Batch Dependent","Train/Eval Gap","Learnable Params","Standard Use"],"rows":[["BatchNorm","Batch dim per channel","Yes","Yes — running stats at eval","γ, β per channel","Image classification (large batch)"],["LayerNorm","Feature dim per sample","No","No","γ, β per feature","Transformers, RNNs, NLP"],["RMSNorm","Feature dim per sample (no mean)","No","No","γ per feature only","LLaMA, Gemma, Mistral, Falcon"],["GroupNorm","Within each channel group per sample","No","No","γ, β per channel","Object detection, segmentation"],["InstanceNorm","Spatial dims per sample per channel","No","No","γ, β per channel (optional)","Style transfer, CycleGAN"]]},{"type":"text","content":"Choose LayerNorm for any Transformer-based architecture. Use RMSNorm when training efficiency matters and mean-centering is not critical. Use GroupNorm when batch sizes are small (≤4) and spatial structure exists. Use InstanceNorm specifically for style transfer where removing per-channel statistics normalizes style information."},{"type":"divider"}]"
---
# Layer Normalization — Sequence Models and Pre/Post-Norm

Layer Normalization (Ba et al. 2016) normalizes activations across the feature dimension of each individual sample, making it batch-size independent and consistent between training and inference. Unlike Batch Normalization which normalizes across the batch dimension, LN operates on each token's feature vector in isolation — a property that makes it the standard normalization choice for Transformers, RNNs, and any architecture processing variable-length sequences.

## Layer Normalization Formula

For an input vector x ∈ ℝᵈ, Layer Normalization computes: μ = (1/d) Σᵢ xᵢ (mean over feature dim), σ² = (1/d) Σᵢ (xᵢ − μ)² (variance over feature dim), x̂ᵢ = (xᵢ − μ) / √(σ² + ε) (normalize), yᵢ = γᵢ x̂ᵢ + βᵢ (scale and shift). The learned parameters γ (scale) and β (shift) have the same dimension as the feature vector, giving the model freedom to undo the normalization if beneficial. ε is a small constant (typically 1e-5) for numerical stability.

```python
import numpy as np
import torch
import torch.nn as nn

def layer_norm_numpy(x, gamma, beta, eps=1e-5):
    # x: (..., features) — normalize over last dimension
    mean = x.mean(axis=-1, keepdims=True)
    var = x.var(axis=-1, keepdims=True, ddof=0)
    x_hat = (x - mean) / np.sqrt(var + eps)
    return gamma * x_hat + beta

np.random.seed(42)
batch, seq, features = 2, 10, 64
x_np = np.random.randn(batch, seq, features).astype(np.float32)
gamma_np = np.ones(features, dtype=np.float32)
beta_np = np.zeros(features, dtype=np.float32)
out_scratch = layer_norm_numpy(x_np, gamma_np, beta_np)

x_torch = torch.tensor(x_np)
ln = nn.LayerNorm(features)
with torch.no_grad():
    ln.weight.fill_(1.0)
    ln.bias.fill_(0.0)
out_torch = ln(x_torch).detach().numpy()

print(f'Max diff scratch vs PyTorch: {np.abs(out_scratch - out_torch).max():.2e}')
print(f'Per-token mean after LN (should ~0): {out_scratch.mean(axis=-1).mean():.6f}')
print(f'Per-token std  after LN (should ~1): {out_scratch.std(axis=-1).mean():.6f}')
```

## Batch Normalization vs Layer Normalization

Batch Normalization normalizes across the batch dimension: for each feature j, BN computes the mean and variance over all samples in the batch. This creates three problems in sequence modeling: (1) statistics depend on batch size — noisy at small batches; (2) different computation at train (batch stats) vs eval (running stats) causing a train/eval gap; (3) variable-length sequences cannot be batched cleanly since padding tokens corrupt batch statistics. LN computes statistics per-sample over the feature dimension, eliminating all three problems.

```python
import torch
import torch.nn as nn

def compare_norms(batch_size, seq_len=10, features=32):
    x = torch.randn(batch_size, seq_len, features)

    ln = nn.LayerNorm(features)
    out_ln = ln(x)
    ln_info = f'mean={out_ln.mean():.3f}, std={out_ln.std():.3f}'

    bn = nn.BatchNorm1d(features)
    x_flat = x.reshape(batch_size * seq_len, features)
    try:
        out_bn = bn(x_flat)
        bn_info = f'mean={out_bn.mean():.3f}, std={out_bn.std():.3f}'
    except RuntimeError as e:
        bn_info = f'ERROR: {str(e)[:60]}'

    print(f'  batch_size={batch_size}:')
    print(f'    LayerNorm  : {ln_info}')
    print(f'    BatchNorm1d: {bn_info}')

print('=== Normalization at different batch sizes ===')
for bs in [8, 4, 2, 1]:
    compare_norms(bs)
print('\nLN is batch-size independent. BN degrades sharply at batch_size=1.')
```

## Pre-Norm and Post-Norm Transformer Architectures

The original Transformer (Vaswani et al. 2017) used Post-LN: y = LN(x + Sublayer(x)). Normalization is applied after the residual addition. Pre-LN (GPT-2, LLaMA, PaLM): y = x + Sublayer(LN(x)). Normalization is applied before each sublayer; the residual stream grows without being bounded by normalization, giving more stable gradient flow. Pre-LN typically requires no learning rate warmup and trains more reliably at depth ≥ 24 layers. Post-LN can achieve marginally better final perplexity but requires careful tuning.

```python
import torch
import torch.nn as nn

class PreNormBlock(nn.Module):
    def __init__(self, d_model, nhead, dim_ff):
        super().__init__()
        self.attn = nn.MultiheadAttention(d_model, nhead, batch_first=True)
        self.ff = nn.Sequential(
            nn.Linear(d_model, dim_ff), nn.GELU(), nn.Linear(dim_ff, d_model))
        self.ln1 = nn.LayerNorm(d_model)
        self.ln2 = nn.LayerNorm(d_model)
    def forward(self, x):
        n = self.ln1(x)
        x = x + self.attn(n, n, n)[0]
        x = x + self.ff(self.ln2(x))
        return x

class PostNormBlock(nn.Module):
    def __init__(self, d_model, nhead, dim_ff):
        super().__init__()
        self.attn = nn.MultiheadAttention(d_model, nhead, batch_first=True)
        self.ff = nn.Sequential(
            nn.Linear(d_model, dim_ff), nn.GELU(), nn.Linear(dim_ff, d_model))
        self.ln1 = nn.LayerNorm(d_model)
        self.ln2 = nn.LayerNorm(d_model)
    def forward(self, x):
        x = self.ln1(x + self.attn(x, x, x)[0])
        x = self.ln2(x + self.ff(x))
        return x

d_model, nhead, dim_ff = 64, 4, 128
x = torch.randn(2, 16, d_model)
pre = PreNormBlock(d_model, nhead, dim_ff)
post = PostNormBlock(d_model, nhead, dim_ff)
print(f'PreNorm  output norm: {pre(x).norm().item():.4f}')
print(f'PostNorm output norm: {post(x).norm().item():.4f}')
print('PreNorm residual grows freely; PostNorm bounded by LN at each sublayer output.')
```

> **Pre-Norm is the Modern Default**: All major LLMs — GPT-2, GPT-3, LLaMA 1/2/3, PaLM, Falcon, Mistral — use Pre-LN. Post-LN (original Transformer) can achieve slightly better final perplexity but requires careful warmup schedules and often diverges in models deeper than 24 layers. For new architectures, start with Pre-LN.

## Why Layer Norm Replaced Batch Norm in Sequence Models

Three properties make LN uniquely suited to sequence modeling: Batch independence — LN statistics are computed per-sample, so normalization is identical at batch_size=1 and batch_size=512. Variable-length compatibility — each token is normalized using only its own feature vector, so sequences of different lengths can be processed without any special handling. Train/eval consistency — LN uses the same formula at training and inference with no running-mean accumulation and no behavioral shift between model.train() and model.eval(). BN violates all three properties.

- Batch independence: LN computes mean/var over the feature dim of each sample — no batch coupling.
- Variable sequences: padding tokens would corrupt BN batch statistics; LN processes each position independently.
- No train/eval gap: BN uses batch stats at train and running stats at eval; LN behavior is identical in both modes.
- Consistent gradient: LN gradient depends only on the local sample — no cross-batch gradient coupling in backward pass.

## Gradient Flow Through Layer Norm

The gradient of the LN output with respect to the input has a centering component: ∂L/∂x ∝ [∂L/∂x̂ − mean(∂L/∂x̂) − x̂ · mean(∂L/∂x̂ · x̂)] / σ. The mean subtraction terms prevent constant gradient components from flowing back, acting as an implicit gradient regularizer. For BN, gradients are coupled across the batch — each sample's gradient depends on all others, which can cause instability when batch size changes between training and inference.

```python
import torch
import torch.nn as nn
import numpy as np

def measure_grad_flow(norm_class, input_shape, **kwargs):
    x = torch.randn(*input_shape, requires_grad=True)
    layer = norm_class(**kwargs)
    out = layer(x)
    loss = out.pow(2).mean()
    loss.backward()
    return x.grad.abs().mean().item(), x.grad.std().item()

B, T, C = 4, 20, 64
ln_mean, ln_std = measure_grad_flow(nn.LayerNorm, (B, T, C), normalized_shape=C)

class BNSeq(nn.Module):
    def __init__(self, num_features):
        super().__init__()
        self.bn = nn.BatchNorm1d(num_features)
    def forward(self, x):
        B, T, C = x.shape
        return self.bn(x.reshape(B * T, C)).reshape(B, T, C)

bn_mean, bn_std = measure_grad_flow(BNSeq, (B, T, C), num_features=C)

print(f'LayerNorm grad: mean={ln_mean:.6f}, std={ln_std:.6f}')
print(f'BatchNorm grad: mean={bn_mean:.6f}, std={bn_std:.6f}')
print('LN gradient is per-sample — no cross-batch coupling in the backward pass.')
```

## Embedding Layer Normalization

Modern LLMs apply LN to the embedding outputs before feeding them into the first transformer block. This bounds the scale of the initial residual stream and prevents early layers from spending capacity on normalization. BERT and RoBERTa apply LN after summing token and positional embeddings. GPT-NeoX uses a separate embedding normalization before and after the embedding lookup. The LN parameters at the embedding layer are learned independently from the LN inside each transformer block.

## Normalization Methods Comparison

| Method | Normalizes Over | Batch Dependent | Train/Eval Gap | Learnable Params | Standard Use |
| --- | --- | --- | --- | --- | --- |
| BatchNorm | Batch dim per channel | Yes | Yes — running stats at eval | γ, β per channel | Image classification (large batch) |
| LayerNorm | Feature dim per sample | No | No | γ, β per feature | Transformers, RNNs, NLP |
| RMSNorm | Feature dim per sample (no mean) | No | No | γ per feature only | LLaMA, Gemma, Mistral, Falcon |
| GroupNorm | Within each channel group per sample | No | No | γ, β per channel | Object detection, segmentation |
| InstanceNorm | Spatial dims per sample per channel | No | No | γ, β per channel (optional) | Style transfer, CycleGAN |

Choose LayerNorm for any Transformer-based architecture. Use RMSNorm when training efficiency matters and mean-centering is not critical. Use GroupNorm when batch sizes are small (≤4) and spatial structure exists. Use InstanceNorm specifically for style transfer where removing per-channel statistics normalizes style information.

---

