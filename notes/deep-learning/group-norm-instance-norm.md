---
title: "Group Norm and Instance Norm — Small Batch Alternatives"
slug: "group-norm-instance-norm"
description: "Implement GroupNorm and InstanceNorm from scratch, demonstrate BN failure at small batch sizes, apply IN for style transfer, and compare all normalization methods across tasks."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Object detection and segmentation models often train with very small batch sizes (1–4 images per GPU) because high-resolution images consume significant memory. Batch Normalization\u0027s statistics become unreliable at these small batch sizes, causing training instability and poor performance. Group Normalization (Wu \u0026 He 2018) and Instance Normalization (Ulyanov et al. 2016) solve this by normalizing without relying on the batch dimension — GN for general small-batch training, IN specifically for style transfer tasks."},{"type":"heading","level":2,"content":"Group Normalization"},{"type":"text","content":"GroupNorm divides the C channels into G groups and normalizes within each group independently. For an input x ∈ ℝ^(B×C×H×W), the channels are reshaped to (B, G, C/G, H, W) and normalization is computed over the (C/G, H, W) dimensions for each group. Special cases: GN with G=1 normalizes over all channels per sample, which equals LayerNorm for image inputs. GN with G=C normalizes each channel independently per sample, which equals InstanceNorm. The G=32 default works well across detection, segmentation, and video tasks."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\n\ndef group_norm_numpy(x, num_groups, gamma, beta, eps=1e-5):\n    # x: (B, C, H, W)\n    B, C, H, W = x.shape\n    assert C % num_groups == 0\n    G = num_groups\n    x_r = x.reshape(B, G, C // G, H, W)\n    # Mean and var over (C/G, H, W) axes per (B, G)\n    mean = x_r.mean(axis=(2, 3, 4), keepdims=True)\n    var  = x_r.var(axis=(2, 3, 4), keepdims=True, ddof=0)\n    x_hat = (x_r - mean) / np.sqrt(var + eps)\n    x_hat = x_hat.reshape(B, C, H, W)\n    # gamma, beta: (C,) -\u003e broadcast over (B, H, W)\n    return gamma[None, :, None, None] * x_hat + beta[None, :, None, None]\n\nB, C, H, W = 2, 16, 8, 8\nnum_groups = 4\nx_np = np.random.randn(B, C, H, W).astype(np.float32)\ngamma_np = np.ones(C, dtype=np.float32)\nbeta_np  = np.zeros(C, dtype=np.float32)\nout_scratch = group_norm_numpy(x_np, num_groups, gamma_np, beta_np)\n\ngn = nn.GroupNorm(num_groups, C)\nout_torch = gn(torch.tensor(x_np)).detach().numpy()\nprint(f\u0027Max diff scratch vs PyTorch GroupNorm: {np.abs(out_scratch - out_torch).max():.2e}\u0027)"},{"type":"heading","level":2,"content":"Instance Normalization"},{"type":"text","content":"InstanceNorm normalizes each sample and each channel independently over the spatial dimensions (H, W). It completely removes the per-instance per-channel mean and variance — normalizing the style statistics. This makes IN ideal for style transfer: given content image C and style image S, normalizing the feature activations of C to match the statistics of S (Adaptive IN / AdaIN) transfers the style. CycleGAN, StyleGAN, and arbitrary neural style transfer all use IN or its variants. IN is equivalent to GN with G=C."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef adaptive_instance_norm(content_feat, style_feat, eps=1e-5):\n    # Align content feature statistics to match style feature statistics\n    # content_feat, style_feat: (B, C, H, W)\n    B, C, H, W = content_feat.shape\n    # Compute content statistics\n    c_mean = content_feat.mean(dim=(2, 3), keepdim=True)\n    c_std  = content_feat.std(dim=(2, 3), keepdim=True) + eps\n    # Compute style statistics\n    s_mean = style_feat.mean(dim=(2, 3), keepdim=True)\n    s_std  = style_feat.std(dim=(2, 3), keepdim=True) + eps\n    # Normalize content then rescale with style statistics\n    normalized = (content_feat - c_mean) / c_std\n    return s_std * normalized + s_mean\n\ntorch.manual_seed(0)\nB, C, H, W = 2, 64, 16, 16\ncontent = torch.randn(B, C, H, W)\nstyle   = torch.randn(B, C, H, W) * 2.5 + 1.0  # different scale and shift\nadain_out = adaptive_instance_norm(content, style)\n\nprint(f\u0027Content mean: {content.mean((2,3)).mean():.3f}, std: {content.std((2,3)).mean():.3f}\u0027)\nprint(f\u0027Style   mean: {style.mean((2,3)).mean():.3f}, std: {style.std((2,3)).mean():.3f}\u0027)\nprint(f\u0027AdaIN   mean: {adain_out.mean((2,3)).mean():.3f}, std: {adain_out.std((2,3)).mean():.3f}\u0027)\nprint(\u0027AdaIN output statistics match style — content structure preserved.\u0027)"},{"type":"heading","level":2,"content":"GN vs BN at Different Batch Sizes"},{"type":"text","content":"Wu \u0026 He (2018) showed that GroupNorm significantly outperforms BatchNorm on COCO object detection at small batch sizes. At batch_size=2 per GPU, GN achieves 34.8 AP vs BN\u0027s 31.3 AP on Mask R-CNN with ResNet-50 FPN. The performance gap closes as batch size increases: at batch_size=32, BN matches or slightly surpasses GN. For modern GPU memory constraints (high-resolution inputs, large models), GN or LN is preferred over BN in detection/segmentation pipelines."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef norm_stats(out_tensor):\n    m = out_tensor.mean().item()\n    s = out_tensor.std().item()\n    return f\u0027mean={m:.3f}, std={s:.3f}\u0027\n\nC, H, W = 32, 16, 16\nnorm_layers = {\n    \u0027GroupNorm(G=8)\u0027: nn.GroupNorm(8, C),\n    \u0027InstanceNorm\u0027 : nn.InstanceNorm2d(C, affine=True),\n    \u0027LayerNorm\u0027    : nn.GroupNorm(1, C),  # GN(G=1) == LN for images\n}\n\nprint(f\u0027{\"\": \u003c20} {\"batch=1\": \u003c25} {\"batch=4\": \u003c25} {\"batch=16\"}\u0027)\nfor name, layer in norm_layers.items():\n    results = []\n    for bs in [1, 4, 16]:\n        x = torch.randn(bs, C, H, W)\n        out = layer(x)\n        results.append(norm_stats(out))\n    print(f\u0027{name: \u003c20} {results[0]: \u003c25} {results[1]: \u003c25} {results[2]}\u0027)\n\nprint(\u0027\\nBN stats for comparison:\u0027)\nbn = nn.BatchNorm2d(C)\nfor bs in [1, 4, 16]:\n    x = torch.randn(bs, C, H, W)\n    try:\n        out = bn(x)\n        print(f\u0027  BatchNorm batch={bs}: {norm_stats(out)}\u0027)\n    except Exception as e:\n        print(f\u0027  BatchNorm batch={bs}: ERROR\u0027)"},{"type":"callout","variant":"warning","title":"GroupNorm for Small Batch Detection and Segmentation","content":"When training Mask R-CNN, DETR, or SegFormer with batch_size \u003c= 4 per GPU, always replace BatchNorm with GroupNorm (G=32 or G=16). BN at small batch sizes produces noisy statistics that destabilize training. Freeze BN (via SyncBatchNorm or BatchNorm frozen=True) is another option when using pretrained backbones, but training new BN layers at small batch is not recommended."},{"type":"heading","level":2,"content":"Relationship Between Normalization Methods"},{"type":"text","content":"All four normalizations share the same computation structure but differ in which dimensions they normalize over. For a 4D tensor (B, C, H, W): BatchNorm normalizes over (B, H, W) per channel — statistics depend on all samples and all spatial positions for each channel. LayerNorm normalizes over (C, H, W) per sample — statistics depend on all channels and spatial positions per sample. GroupNorm normalizes over (C/G, H, W) per (sample, group). InstanceNorm normalizes over (H, W) per (sample, channel). This unifying view makes it easy to switch between normalizations in code."},{"type":"list","ordered":false,"items":["GN(G=1) = LayerNorm for image tensors (normalize over all C, H, W per sample).","GN(G=C) = InstanceNorm (normalize over H, W per sample per channel).","BN with batch_size=1 and spatial collapse = InstanceNorm (numerically equivalent but different API).","All normalizations share the same affine transform: y = γx̂ + β with learned per-channel γ, β.","SyncBatchNorm: allreduce batch statistics across GPUs — allows effective batch normalization even at small per-device batch sizes in distributed training."]},{"type":"text","content":"Choosing the number of groups G in GroupNorm requires a tradeoff: fewer groups (small G) means larger group size and more stable statistics, but less fine-grained normalization. More groups (large G) gives finer-grained normalization but smaller per-group statistics. G=32 is the standard for detection and segmentation models. For narrow layers with fewer than 32 channels, use G=4 or G=8. The group size C/G should always be at least 8 to maintain reliable within-group statistics."},{"type":"heading","level":2,"content":"Benchmark: Classification vs Detection"},{"type":"text","content":"The benchmark below measures forward-pass wall-clock time across normalization methods at different batch sizes on a (B, 64, 32, 32) feature map. GN, LN, and IN are batch-size independent — their cost scales linearly with input size regardless of batch. BN adds overhead for running-stat updates during training. On GPU with fused kernels (cuDNN), BN benefits from highly optimized CUDA code paths at large batch sizes."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\n\nC, H, W = 64, 32, 32\nnorm_configs = [\n    (\u0027BatchNorm2d\u0027, nn.BatchNorm2d(C)),\n    (\u0027GroupNorm(G=32)\u0027, nn.GroupNorm(32, C)),\n    (\u0027GroupNorm(G=1/LN)\u0027, nn.GroupNorm(1, C)),\n    (\u0027InstanceNorm2d\u0027, nn.InstanceNorm2d(C, affine=True)),\n]\n\nprint(\u0027=== Throughput benchmark (forward pass only, ms per call) ===\u0027)\nfor batch_size in [2, 8, 32]:\n    print(f\u0027\\n  batch_size={batch_size}:\u0027)\n    x = torch.randn(batch_size, C, H, W)\n    for name, layer in norm_configs:\n        times = []\n        for _ in range(200):\n            t0 = time.perf_counter()\n            _ = layer(x)\n            times.append((time.perf_counter() - t0) * 1000)\n        avg = sum(times[20:]) / len(times[20:])  # skip warmup\n        print(f\u0027    {name:\u003c25}: {avg:.3f} ms\u0027)"},{"type":"heading","level":2,"content":"Normalization Methods Reference Table"},{"type":"table","headers":["Method","Normalizes Over","Batch Dependent","Train/Eval Gap","Typical Use Case"],"rows":[["BatchNorm","(B, H, W) per channel","Yes","Yes","Image classification, large batch (≥16)"],["LayerNorm","(C, H, W) per sample","No","No","Transformers, NLP, BERT, T5"],["GroupNorm","(C/G, H, W) per (B, G)","No","No","Object detection, segmentation, small batch"],["InstanceNorm","(H, W) per (B, C)","No","No","Style transfer, CycleGAN, image-to-image"],["RMSNorm","Feature dim per sample (no mean)","No","No","LLM pre-training, LLaMA, Gemma, Mistral"]]},{"type":"text","content":"GroupNorm with G=32 is the recommended default for any vision task where batch size per GPU is 8 or fewer. For classification with large batches (≥32), BatchNorm remains competitive. Instance Normalization is specialized for style transfer and should not be used as a general-purpose replacement for BN or GN — removing per-instance statistics also removes discriminative information that classification tasks rely on."},{"type":"divider"}]"
---
# Group Norm and Instance Norm — Small Batch Alternatives

Object detection and segmentation models often train with very small batch sizes (1–4 images per GPU) because high-resolution images consume significant memory. Batch Normalization's statistics become unreliable at these small batch sizes, causing training instability and poor performance. Group Normalization (Wu & He 2018) and Instance Normalization (Ulyanov et al. 2016) solve this by normalizing without relying on the batch dimension — GN for general small-batch training, IN specifically for style transfer tasks.

## Group Normalization

GroupNorm divides the C channels into G groups and normalizes within each group independently. For an input x ∈ ℝ^(B×C×H×W), the channels are reshaped to (B, G, C/G, H, W) and normalization is computed over the (C/G, H, W) dimensions for each group. Special cases: GN with G=1 normalizes over all channels per sample, which equals LayerNorm for image inputs. GN with G=C normalizes each channel independently per sample, which equals InstanceNorm. The G=32 default works well across detection, segmentation, and video tasks.

```python
import numpy as np
import torch
import torch.nn as nn

def group_norm_numpy(x, num_groups, gamma, beta, eps=1e-5):
    # x: (B, C, H, W)
    B, C, H, W = x.shape
    assert C % num_groups == 0
    G = num_groups
    x_r = x.reshape(B, G, C // G, H, W)
    # Mean and var over (C/G, H, W) axes per (B, G)
    mean = x_r.mean(axis=(2, 3, 4), keepdims=True)
    var  = x_r.var(axis=(2, 3, 4), keepdims=True, ddof=0)
    x_hat = (x_r - mean) / np.sqrt(var + eps)
    x_hat = x_hat.reshape(B, C, H, W)
    # gamma, beta: (C,) -> broadcast over (B, H, W)
    return gamma[None, :, None, None] * x_hat + beta[None, :, None, None]

B, C, H, W = 2, 16, 8, 8
num_groups = 4
x_np = np.random.randn(B, C, H, W).astype(np.float32)
gamma_np = np.ones(C, dtype=np.float32)
beta_np  = np.zeros(C, dtype=np.float32)
out_scratch = group_norm_numpy(x_np, num_groups, gamma_np, beta_np)

gn = nn.GroupNorm(num_groups, C)
out_torch = gn(torch.tensor(x_np)).detach().numpy()
print(f'Max diff scratch vs PyTorch GroupNorm: {np.abs(out_scratch - out_torch).max():.2e}')
```

## Instance Normalization

InstanceNorm normalizes each sample and each channel independently over the spatial dimensions (H, W). It completely removes the per-instance per-channel mean and variance — normalizing the style statistics. This makes IN ideal for style transfer: given content image C and style image S, normalizing the feature activations of C to match the statistics of S (Adaptive IN / AdaIN) transfers the style. CycleGAN, StyleGAN, and arbitrary neural style transfer all use IN or its variants. IN is equivalent to GN with G=C.

```python
import torch
import torch.nn as nn
import numpy as np

def adaptive_instance_norm(content_feat, style_feat, eps=1e-5):
    # Align content feature statistics to match style feature statistics
    # content_feat, style_feat: (B, C, H, W)
    B, C, H, W = content_feat.shape
    # Compute content statistics
    c_mean = content_feat.mean(dim=(2, 3), keepdim=True)
    c_std  = content_feat.std(dim=(2, 3), keepdim=True) + eps
    # Compute style statistics
    s_mean = style_feat.mean(dim=(2, 3), keepdim=True)
    s_std  = style_feat.std(dim=(2, 3), keepdim=True) + eps
    # Normalize content then rescale with style statistics
    normalized = (content_feat - c_mean) / c_std
    return s_std * normalized + s_mean

torch.manual_seed(0)
B, C, H, W = 2, 64, 16, 16
content = torch.randn(B, C, H, W)
style   = torch.randn(B, C, H, W) * 2.5 + 1.0  # different scale and shift
adain_out = adaptive_instance_norm(content, style)

print(f'Content mean: {content.mean((2,3)).mean():.3f}, std: {content.std((2,3)).mean():.3f}')
print(f'Style   mean: {style.mean((2,3)).mean():.3f}, std: {style.std((2,3)).mean():.3f}')
print(f'AdaIN   mean: {adain_out.mean((2,3)).mean():.3f}, std: {adain_out.std((2,3)).mean():.3f}')
print('AdaIN output statistics match style — content structure preserved.')
```

## GN vs BN at Different Batch Sizes

Wu & He (2018) showed that GroupNorm significantly outperforms BatchNorm on COCO object detection at small batch sizes. At batch_size=2 per GPU, GN achieves 34.8 AP vs BN's 31.3 AP on Mask R-CNN with ResNet-50 FPN. The performance gap closes as batch size increases: at batch_size=32, BN matches or slightly surpasses GN. For modern GPU memory constraints (high-resolution inputs, large models), GN or LN is preferred over BN in detection/segmentation pipelines.

```python
import torch
import torch.nn as nn
import numpy as np

def norm_stats(out_tensor):
    m = out_tensor.mean().item()
    s = out_tensor.std().item()
    return f'mean={m:.3f}, std={s:.3f}'

C, H, W = 32, 16, 16
norm_layers = {
    'GroupNorm(G=8)': nn.GroupNorm(8, C),
    'InstanceNorm' : nn.InstanceNorm2d(C, affine=True),
    'LayerNorm'    : nn.GroupNorm(1, C),  # GN(G=1) == LN for images
}

print(f'{"": <20} {"batch=1": <25} {"batch=4": <25} {"batch=16"}')
for name, layer in norm_layers.items():
    results = []
    for bs in [1, 4, 16]:
        x = torch.randn(bs, C, H, W)
        out = layer(x)
        results.append(norm_stats(out))
    print(f'{name: <20} {results[0]: <25} {results[1]: <25} {results[2]}')

print('\nBN stats for comparison:')
bn = nn.BatchNorm2d(C)
for bs in [1, 4, 16]:
    x = torch.randn(bs, C, H, W)
    try:
        out = bn(x)
        print(f'  BatchNorm batch={bs}: {norm_stats(out)}')
    except Exception as e:
        print(f'  BatchNorm batch={bs}: ERROR')
```

> **GroupNorm for Small Batch Detection and Segmentation**: When training Mask R-CNN, DETR, or SegFormer with batch_size <= 4 per GPU, always replace BatchNorm with GroupNorm (G=32 or G=16). BN at small batch sizes produces noisy statistics that destabilize training. Freeze BN (via SyncBatchNorm or BatchNorm frozen=True) is another option when using pretrained backbones, but training new BN layers at small batch is not recommended.

## Relationship Between Normalization Methods

All four normalizations share the same computation structure but differ in which dimensions they normalize over. For a 4D tensor (B, C, H, W): BatchNorm normalizes over (B, H, W) per channel — statistics depend on all samples and all spatial positions for each channel. LayerNorm normalizes over (C, H, W) per sample — statistics depend on all channels and spatial positions per sample. GroupNorm normalizes over (C/G, H, W) per (sample, group). InstanceNorm normalizes over (H, W) per (sample, channel). This unifying view makes it easy to switch between normalizations in code.

- GN(G=1) = LayerNorm for image tensors (normalize over all C, H, W per sample).
- GN(G=C) = InstanceNorm (normalize over H, W per sample per channel).
- BN with batch_size=1 and spatial collapse = InstanceNorm (numerically equivalent but different API).
- All normalizations share the same affine transform: y = γx̂ + β with learned per-channel γ, β.
- SyncBatchNorm: allreduce batch statistics across GPUs — allows effective batch normalization even at small per-device batch sizes in distributed training.

Choosing the number of groups G in GroupNorm requires a tradeoff: fewer groups (small G) means larger group size and more stable statistics, but less fine-grained normalization. More groups (large G) gives finer-grained normalization but smaller per-group statistics. G=32 is the standard for detection and segmentation models. For narrow layers with fewer than 32 channels, use G=4 or G=8. The group size C/G should always be at least 8 to maintain reliable within-group statistics.

## Benchmark: Classification vs Detection

The benchmark below measures forward-pass wall-clock time across normalization methods at different batch sizes on a (B, 64, 32, 32) feature map. GN, LN, and IN are batch-size independent — their cost scales linearly with input size regardless of batch. BN adds overhead for running-stat updates during training. On GPU with fused kernels (cuDNN), BN benefits from highly optimized CUDA code paths at large batch sizes.

```python
import torch
import torch.nn as nn
import time

C, H, W = 64, 32, 32
norm_configs = [
    ('BatchNorm2d', nn.BatchNorm2d(C)),
    ('GroupNorm(G=32)', nn.GroupNorm(32, C)),
    ('GroupNorm(G=1/LN)', nn.GroupNorm(1, C)),
    ('InstanceNorm2d', nn.InstanceNorm2d(C, affine=True)),
]

print('=== Throughput benchmark (forward pass only, ms per call) ===')
for batch_size in [2, 8, 32]:
    print(f'\n  batch_size={batch_size}:')
    x = torch.randn(batch_size, C, H, W)
    for name, layer in norm_configs:
        times = []
        for _ in range(200):
            t0 = time.perf_counter()
            _ = layer(x)
            times.append((time.perf_counter() - t0) * 1000)
        avg = sum(times[20:]) / len(times[20:])  # skip warmup
        print(f'    {name:<25}: {avg:.3f} ms')
```

## Normalization Methods Reference Table

| Method | Normalizes Over | Batch Dependent | Train/Eval Gap | Typical Use Case |
| --- | --- | --- | --- | --- |
| BatchNorm | (B, H, W) per channel | Yes | Yes | Image classification, large batch (≥16) |
| LayerNorm | (C, H, W) per sample | No | No | Transformers, NLP, BERT, T5 |
| GroupNorm | (C/G, H, W) per (B, G) | No | No | Object detection, segmentation, small batch |
| InstanceNorm | (H, W) per (B, C) | No | No | Style transfer, CycleGAN, image-to-image |
| RMSNorm | Feature dim per sample (no mean) | No | No | LLM pre-training, LLaMA, Gemma, Mistral |

GroupNorm with G=32 is the recommended default for any vision task where batch size per GPU is 8 or fewer. For classification with large batches (≥32), BatchNorm remains competitive. Instance Normalization is specialized for style transfer and should not be used as a general-purpose replacement for BN or GN — removing per-instance statistics also removes discriminative information that classification tasks rely on.

---

