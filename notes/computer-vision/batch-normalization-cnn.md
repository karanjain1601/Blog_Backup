---
title: "Batch Normalization in CNNs"
slug: "batch-normalization-cnn"
description: "Batch normalization for convolutional layers — how it normalizes per-channel statistics across spatial locations, placement conventions, training vs eval mode differences, and layer norm alternatives."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Batch normalization (BN) was introduced by Ioffe and Szegedy in 2015 and became a standard building block of CNNs. It normalizes activations within each mini-batch, stabilizing the distribution of inputs to each layer. This reduces internal covariate shift, enabling higher learning rates, reducing sensitivity to initialization, and providing mild regularization that reduces the need for dropout."},{"type":"text","content":"In convolutional layers, BN operates per-channel: for each channel c, it computes the mean and variance across the batch dimension B and spatial dimensions H and W simultaneously. This is different from fully connected BN, which normalizes per-feature across the batch only. The spatial sharing makes BN for conv layers parameter-efficient: only 2 × C learnable parameters (γ and β) regardless of spatial size."},{"type":"heading","level":2,"content":"BN Math for Convolutional Layers"},{"type":"text","content":"For a feature map x of shape [B, C, H, W], BN computes per-channel statistics: μ_c = mean over [B, H, W], σ²_c = variance over [B, H, W]. Normalized: x̂ = (x − μ_c) / √(σ²_c + ε). Output: y = γ_c · x̂ + β_c, where γ and β are learnable scalars per channel. During training, batch statistics are used. During inference, running exponential moving averages of μ and σ² are used instead."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nbn = nn.BatchNorm2d(num_features=64, eps=1e-5, momentum=0.1)\nprint(\"Gamma (weight):\", bn.weight.shape)  # [64]\nprint(\"Beta  (bias):  \", bn.bias.shape)    # [64]\nprint(\"Running mean:  \", bn.running_mean.shape)  # [64]\nprint(\"Running var:   \", bn.running_var.shape)   # [64]\n\nx = torch.randn(8, 64, 16, 16)  # [B, C, H, W]\nbn.train()\ntrain_out = bn(x)   # Uses batch stats, updates running stats\nbn.eval()\neval_out = bn(x)    # Uses running stats\nprint(\"Max diff train vs eval:\", (train_out - eval_out).abs().max().item())"},{"type":"code","language":"python","content":"import torch\n\ndef manual_bn_conv(x, gamma, beta, eps=1e-5):\n    \"\"\"Manual BN forward for [B, C, H, W] input.\"\"\"\n    # Compute per-channel mean and var over [B, H, W]\n    mean = x.mean(dim=(0, 2, 3), keepdim=True)  # [1, C, 1, 1]\n    var  = x.var(dim=(0, 2, 3), keepdim=True, unbiased=False)\n    x_hat = (x - mean) / (var + eps).sqrt()\n    return gamma.view(1, -1, 1, 1) * x_hat + beta.view(1, -1, 1, 1)\n\nC = 16\nx = torch.randn(4, C, 8, 8)\ngamma = torch.ones(C); beta = torch.zeros(C)\nout = manual_bn_conv(x, gamma, beta)\nprint(\"Output shape:\", out.shape)          # [4, 16, 8, 8]\nprint(\"Channel mean ~0:\", out.mean(dim=(0,2,3)).abs().max().item() \u003c 1e-5)"},{"type":"heading","level":2,"content":"Placement: Before or After Activation"},{"type":"text","content":"The original BN paper placed normalization after the linear transform and before the activation: Conv → BN → ReLU. This is still the most common convention. An alternative, sometimes called \u0027pre-activation\u0027 (He et al., Identity Mappings in ResNets), places BN before the conv: BN → ReLU → Conv. Pre-activation BN can improve gradient flow in very deep networks and makes residual identity shortcuts cleaner, but is less universally adopted."},{"type":"heading","level":2,"content":"Train vs Eval Mode"},{"type":"text","content":"The most important operational difference in BN is between training and evaluation. During training, BN uses mini-batch statistics (mean and variance computed from the current batch). This introduces stochasticity beneficial for generalization. During inference, batch statistics are unavailable or unreliable (batch size may be 1), so BN uses running exponential moving averages accumulated during training. Forgetting to switch modes is a very common bug."},{"type":"callout","variant":"warning","content":"BatchNorm behaves differently in train vs eval mode — always call model.eval() at inference or BN will use batch statistics instead of running statistics, causing performance degradation."},{"type":"heading","level":2,"content":"Layer Norm and Group Norm Alternatives"},{"type":"text","content":"BN\u0027s dependence on batch size makes it problematic for small batches (batch size 1–2 causes noisy statistics) and distributed training across GPUs. Alternatives: Group Normalization (GN) normalizes over groups of channels within a single sample, eliminating batch-size dependence. Layer Normalization normalizes over all channels and spatial dims for one sample. Instance Normalization normalizes per-sample per-channel. RMSNorm (used in transformers) omits the mean centering step."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nB, C, H, W = 4, 32, 16, 16\nx = torch.randn(B, C, H, W)\n\n# Group Norm: 8 groups of 4 channels each — no batch dependency\ngn = nn.GroupNorm(num_groups=8, num_channels=C)\nout_gn = gn(x)\nprint(\"GroupNorm output:\", out_gn.shape)  # [4, 32, 16, 16]\n\n# Batch Norm for comparison\nbn = nn.BatchNorm2d(C)\nout_bn = bn(x)\nprint(\"BatchNorm output:\", out_bn.shape)  # [4, 32, 16, 16]\n\n# At batch_size=1, GN is stable, BN is noisy\nx1 = torch.randn(1, C, H, W)\nprint(\"GN at bs=1:\", gn(x1).std().item())   # ~1.0, stable"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nB, C, H, W = 4, 32, 8, 8\nx = torch.randn(B, C, H, W)\n\n# BN before ReLU (original placement)\nconv_bn_relu = nn.Sequential(\n    nn.Conv2d(C, C, 3, padding=1),\n    nn.BatchNorm2d(C),\n    nn.ReLU(inplace=True)\n)\n\n# BN after ReLU (pre-activation / He 2016 variant)\nconv_relu_bn = nn.Sequential(\n    nn.Conv2d(C, C, 3, padding=1),\n    nn.ReLU(inplace=True),\n    nn.BatchNorm2d(C)\n)\n\nout1 = conv_bn_relu(x)\nout2 = conv_relu_bn(x)\nprint(\"BN-before: dead neurons\", (out1 == 0).float().mean().item())\nprint(\"BN-after:  dead neurons\", (out2 == 0).float().mean().item())"},{"type":"table","headers":["Norm Type","Normalizes Over","Batch-Size Sensitive","Small Batch Works","Use Case"],"rows":[["BatchNorm","Batch B + spatial H×W per channel","Yes","No (bs\u003c8 unstable)","Standard CNNs, large-batch vision training"],["LayerNorm","All channels + spatial per sample","No","Yes","Transformers, ViT, NLP"],["GroupNorm","Channel groups per sample","No","Yes","Object detection (bs=1–2), segmentation"],["InstanceNorm","Spatial H×W per channel per sample","No","Yes","Style transfer, image synthesis"],["RMSNorm","All dims per sample (no mean)","No","Yes","LLMs, modern transformers (Llama, Gemma)"]]},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"BatchNorm is the default normalization for CNN classification backbones trained with large batch sizes. Always remember the train/eval mode distinction — failing to call model.eval() is one of the most common deployment bugs. The running mean and running variance buffers are not parameters (no gradients) but are part of the model state and must be included in checkpoint saves and loads."},{"type":"text","content":"For detection and segmentation tasks where batch size is small (2–4 images, each with many crops), Group Normalization outperforms BatchNorm. For transformer-based vision models (ViT, Swin), Layer Normalization is preferred. The choice of normalization layer significantly affects training stability and final accuracy — treat it as a first-class architectural decision alongside the choice of activation function and optimizer."}]"
---
# Batch Normalization in CNNs

## Overview

Batch normalization (BN) was introduced by Ioffe and Szegedy in 2015 and became a standard building block of CNNs. It normalizes activations within each mini-batch, stabilizing the distribution of inputs to each layer. This reduces internal covariate shift, enabling higher learning rates, reducing sensitivity to initialization, and providing mild regularization that reduces the need for dropout.

In convolutional layers, BN operates per-channel: for each channel c, it computes the mean and variance across the batch dimension B and spatial dimensions H and W simultaneously. This is different from fully connected BN, which normalizes per-feature across the batch only. The spatial sharing makes BN for conv layers parameter-efficient: only 2 × C learnable parameters (γ and β) regardless of spatial size.

## BN Math for Convolutional Layers

For a feature map x of shape [B, C, H, W], BN computes per-channel statistics: μ_c = mean over [B, H, W], σ²_c = variance over [B, H, W]. Normalized: x̂ = (x − μ_c) / √(σ²_c + ε). Output: y = γ_c · x̂ + β_c, where γ and β are learnable scalars per channel. During training, batch statistics are used. During inference, running exponential moving averages of μ and σ² are used instead.

```python
import torch
import torch.nn as nn

bn = nn.BatchNorm2d(num_features=64, eps=1e-5, momentum=0.1)
print("Gamma (weight):", bn.weight.shape)  # [64]
print("Beta  (bias):  ", bn.bias.shape)    # [64]
print("Running mean:  ", bn.running_mean.shape)  # [64]
print("Running var:   ", bn.running_var.shape)   # [64]

x = torch.randn(8, 64, 16, 16)  # [B, C, H, W]
bn.train()
train_out = bn(x)   # Uses batch stats, updates running stats
bn.eval()
eval_out = bn(x)    # Uses running stats
print("Max diff train vs eval:", (train_out - eval_out).abs().max().item())
```

```python
import torch

def manual_bn_conv(x, gamma, beta, eps=1e-5):
    """Manual BN forward for [B, C, H, W] input."""
    # Compute per-channel mean and var over [B, H, W]
    mean = x.mean(dim=(0, 2, 3), keepdim=True)  # [1, C, 1, 1]
    var  = x.var(dim=(0, 2, 3), keepdim=True, unbiased=False)
    x_hat = (x - mean) / (var + eps).sqrt()
    return gamma.view(1, -1, 1, 1) * x_hat + beta.view(1, -1, 1, 1)

C = 16
x = torch.randn(4, C, 8, 8)
gamma = torch.ones(C); beta = torch.zeros(C)
out = manual_bn_conv(x, gamma, beta)
print("Output shape:", out.shape)          # [4, 16, 8, 8]
print("Channel mean ~0:", out.mean(dim=(0,2,3)).abs().max().item() < 1e-5)
```

## Placement: Before or After Activation

The original BN paper placed normalization after the linear transform and before the activation: Conv → BN → ReLU. This is still the most common convention. An alternative, sometimes called 'pre-activation' (He et al., Identity Mappings in ResNets), places BN before the conv: BN → ReLU → Conv. Pre-activation BN can improve gradient flow in very deep networks and makes residual identity shortcuts cleaner, but is less universally adopted.

## Train vs Eval Mode

The most important operational difference in BN is between training and evaluation. During training, BN uses mini-batch statistics (mean and variance computed from the current batch). This introduces stochasticity beneficial for generalization. During inference, batch statistics are unavailable or unreliable (batch size may be 1), so BN uses running exponential moving averages accumulated during training. Forgetting to switch modes is a very common bug.

> **warning**: BatchNorm behaves differently in train vs eval mode — always call model.eval() at inference or BN will use batch statistics instead of running statistics, causing performance degradation.

## Layer Norm and Group Norm Alternatives

BN's dependence on batch size makes it problematic for small batches (batch size 1–2 causes noisy statistics) and distributed training across GPUs. Alternatives: Group Normalization (GN) normalizes over groups of channels within a single sample, eliminating batch-size dependence. Layer Normalization normalizes over all channels and spatial dims for one sample. Instance Normalization normalizes per-sample per-channel. RMSNorm (used in transformers) omits the mean centering step.

```python
import torch
import torch.nn as nn

B, C, H, W = 4, 32, 16, 16
x = torch.randn(B, C, H, W)

# Group Norm: 8 groups of 4 channels each — no batch dependency
gn = nn.GroupNorm(num_groups=8, num_channels=C)
out_gn = gn(x)
print("GroupNorm output:", out_gn.shape)  # [4, 32, 16, 16]

# Batch Norm for comparison
bn = nn.BatchNorm2d(C)
out_bn = bn(x)
print("BatchNorm output:", out_bn.shape)  # [4, 32, 16, 16]

# At batch_size=1, GN is stable, BN is noisy
x1 = torch.randn(1, C, H, W)
print("GN at bs=1:", gn(x1).std().item())   # ~1.0, stable
```

```python
import torch
import torch.nn as nn

B, C, H, W = 4, 32, 8, 8
x = torch.randn(B, C, H, W)

# BN before ReLU (original placement)
conv_bn_relu = nn.Sequential(
    nn.Conv2d(C, C, 3, padding=1),
    nn.BatchNorm2d(C),
    nn.ReLU(inplace=True)
)

# BN after ReLU (pre-activation / He 2016 variant)
conv_relu_bn = nn.Sequential(
    nn.Conv2d(C, C, 3, padding=1),
    nn.ReLU(inplace=True),
    nn.BatchNorm2d(C)
)

out1 = conv_bn_relu(x)
out2 = conv_relu_bn(x)
print("BN-before: dead neurons", (out1 == 0).float().mean().item())
print("BN-after:  dead neurons", (out2 == 0).float().mean().item())
```

| Norm Type | Normalizes Over | Batch-Size Sensitive | Small Batch Works | Use Case |
| --- | --- | --- | --- | --- |
| BatchNorm | Batch B + spatial H×W per channel | Yes | No (bs<8 unstable) | Standard CNNs, large-batch vision training |
| LayerNorm | All channels + spatial per sample | No | Yes | Transformers, ViT, NLP |
| GroupNorm | Channel groups per sample | No | Yes | Object detection (bs=1–2), segmentation |
| InstanceNorm | Spatial H×W per channel per sample | No | Yes | Style transfer, image synthesis |
| RMSNorm | All dims per sample (no mean) | No | Yes | LLMs, modern transformers (Llama, Gemma) |

## Key Takeaways

BatchNorm is the default normalization for CNN classification backbones trained with large batch sizes. Always remember the train/eval mode distinction — failing to call model.eval() is one of the most common deployment bugs. The running mean and running variance buffers are not parameters (no gradients) but are part of the model state and must be included in checkpoint saves and loads.

For detection and segmentation tasks where batch size is small (2–4 images, each with many crops), Group Normalization outperforms BatchNorm. For transformer-based vision models (ViT, Swin), Layer Normalization is preferred. The choice of normalization layer significantly affects training stability and final accuracy — treat it as a first-class architectural decision alongside the choice of activation function and optimizer.

