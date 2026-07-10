---
title: "Once-for-All — Train Once, Deploy Many Architectures"
slug: "once-for-all-ofa"
description: "OFA trains a single supernet with elastic kernel, depth, and width so any subnet can be extracted for any hardware target without retraining. Covers progressive shrinking, in-place distillation, elastic kernel sharing, subnet search with latency lookup tables, and comparison with MobileNetV3 and DARTS."
tags: ["deep-learning", "model-compression", "pruning", "quantization"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Standard NAS finds one architecture per hardware target. Deploying a model to 10 different devices (phone, tablet, server, IoT) requires 10 separate NAS runs, each potentially days of compute. Once-for-All (OFA, Cai et al. 2020) decouples training from search: a single supernet is trained once, and arbitrary subnets — defined by depth, width, kernel size, and resolution — can be extracted and deployed without any retraining. Each subnet achieves accuracy close to the equivalent standalone model."},{"type":"heading","level":2,"content":"OFA Search Space"},{"type":"text","content":"The OFA supernet is built from MobileNetV3-like inverted residual blocks. The elastic dimensions are: (1) kernel size per layer ∈ {3, 5, 7}, (2) depth (number of blocks per stage) ∈ {2, 3, 4}, (3) expand ratio (width multiplier inside blocks) ∈ {3, 4, 6}, and (4) input resolution ∈ {128, 160, 192, 224}. The total number of possible subnets exceeds 10^19, covering a continuous Pareto frontier from 150M to 600M FLOPs."},{"type":"heading","level":2,"content":"Elastic Kernel Sharing"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass ElasticKernelConv(nn.Module):\n    \"\"\"\n    A single conv weight of size 7x7 that can act as 7x7, 5x5, or 3x3\n    by extracting the center sub-kernel (shared weights).\n    \"\"\"\n\n    def __init__(self, in_channels: int, out_channels: int, max_kernel: int = 7):\n        super().__init__()\n        assert max_kernel in (7, 5, 3), \u0027max_kernel must be 7, 5, or 3\u0027\n        self.max_kernel = max_kernel\n        # All kernel sizes share from this single weight tensor\n        self.weight = nn.Parameter(\n            torch.randn(out_channels, in_channels, max_kernel, max_kernel)\n            * (2 / (in_channels * max_kernel ** 2)) ** 0.5\n        )\n        self.bias = nn.Parameter(torch.zeros(out_channels))\n        # Learnable transformation matrices to adapt center kernel for smaller sizes\n        self.transforms = nn.ParameterDict()\n        for ks in [k for k in [3, 5, 7] if k \u003c max_kernel]:\n            self.transforms[str(ks)] = nn.Parameter(torch.eye(ks * ks))\n\n    def _extract_sub_kernel(self, kernel_size: int) -\u003e torch.Tensor:\n        if kernel_size == self.max_kernel:\n            return self.weight\n        # Extract center crop\n        start = (self.max_kernel - kernel_size) // 2\n        sub = self.weight[:, :, start:start+kernel_size, start:start+kernel_size]\n        # Apply learned linear transformation (shape-preserving)\n        C_out, C_in = sub.shape[:2]\n        sub_flat = sub.reshape(C_out * C_in, -1)  # (..., ks*ks)\n        T = self.transforms[str(kernel_size)]      # (ks*ks, ks*ks)\n        sub_transformed = (sub_flat @ T).reshape(C_out, C_in, kernel_size, kernel_size)\n        return sub_transformed\n\n    def forward(self, x: torch.Tensor, kernel_size: int = None) -\u003e torch.Tensor:\n        if kernel_size is None:\n            kernel_size = self.max_kernel\n        W = self._extract_sub_kernel(kernel_size)\n        pad = kernel_size // 2\n        return F.conv2d(x, W, self.bias, padding=pad)\n\n# Demo: same weights, different kernel sizes\nelastic_conv = ElasticKernelConv(16, 32, max_kernel=7)\nx = torch.randn(2, 16, 8, 8)\nfor ks in [3, 5, 7]:\n    out = elastic_conv(x, kernel_size=ks)\n    print(f\u0027kernel_size={ks}: input {x.shape} -\u003e output {out.shape}\u0027)"},{"type":"heading","level":2,"content":"Progressive Shrinking Training"},{"type":"text","content":"Training the full supernet from scratch is difficult: all subnets share weights, and small subnets interfere with large ones. Progressive shrinking solves this by training in stages: (1) train the full network (largest kernel, most layers, widest expand ratio) to convergence; (2) add elastic kernel by training with randomly sampled kernel sizes while distilling from the full-kernel subnet; (3) add elastic depth by randomly dropping layers; (4) add elastic width. Each stage uses in-place knowledge distillation: the teacher is the same supernet evaluated with the current stage\u0027s maximum configuration."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport random\n\ndef progressive_shrinking_step(supernet, x, y_true, criterion,\n                               stage=\u0027kernel\u0027,\n                               kernel_choices=(3, 5, 7),\n                               depth_choices=(2, 3, 4)):\n    \"\"\"\n    One training step with progressive shrinking and in-place distillation.\n    Teacher: supernet with max config. Student: random smaller config.\n    \"\"\"\n    supernet.eval()\n    # Teacher forward: always max config\n    with torch.no_grad():\n        teacher_logits = supernet(x, kernel_size=max(kernel_choices),\n                                  depth=max(depth_choices))\n        teacher_probs = F.softmax(teacher_logits / 4.0, dim=-1)  # T=4 temperature\n\n    supernet.train()\n    # Student forward: random smaller config\n    if stage == \u0027kernel\u0027:\n        ks = random.choice(kernel_choices)\n        student_logits = supernet(x, kernel_size=ks, depth=max(depth_choices))\n    elif stage == \u0027depth\u0027:\n        ks = random.choice(kernel_choices)\n        d = random.choice(depth_choices)\n        student_logits = supernet(x, kernel_size=ks, depth=d)\n    else:\n        student_logits = supernet(x, kernel_size=max(kernel_choices),\n                                  depth=max(depth_choices))\n\n    # Combined loss: task loss + KD loss from teacher\n    task_loss = criterion(student_logits, y_true)\n    kd_loss = F.kl_div(\n        F.log_softmax(student_logits / 4.0, dim=-1),\n        teacher_probs,\n        reduction=\u0027batchmean\u0027\n    ) * (4.0 ** 2)  # scale by T^2\n\n    total_loss = 0.5 * task_loss + 0.5 * kd_loss\n    return total_loss, task_loss.item(), kd_loss.item()\n\nprint(\u0027Progressive shrinking: full -\u003e elastic kernel -\u003e elastic depth -\u003e elastic width\u0027)"},{"type":"heading","level":2,"content":"Subnet Search with Latency Lookup"},{"type":"code","language":"python","content":"import torch\nimport random\nfrom itertools import product\n\n# Precomputed latency lookup table (ms) for each op on target device\n# In practice, measured by profiling each op independently\nLATENCY_LUT = {\n    (\u0027conv3\u0027, 2): 1.2, (\u0027conv3\u0027, 3): 1.8, (\u0027conv3\u0027, 4): 2.4,\n    (\u0027conv5\u0027, 2): 2.1, (\u0027conv5\u0027, 3): 3.2, (\u0027conv5\u0027, 4): 4.3,\n    (\u0027conv7\u0027, 2): 3.5, (\u0027conv7\u0027, 3): 5.2, (\u0027conv7\u0027, 4): 6.9,\n}\n\ndef estimate_latency(subnet_config: dict) -\u003e float:\n    \"\"\"Estimate latency from lookup table without running the model.\"\"\"\n    total = 0.0\n    for stage_idx, (kernel, depth) in enumerate(\n        zip(subnet_config[\u0027kernels\u0027], subnet_config[\u0027depths\u0027])\n    ):\n        key = (f\u0027conv{kernel}\u0027, depth)\n        total += LATENCY_LUT.get(key, 3.0)  # default 3ms if not in table\n    return total\n\ndef evolutionary_subnet_search(n_iterations=100, latency_budget_ms=12.0,\n                               population_size=50):\n    \"\"\"Simple evolutionary search over subnet configurations.\"\"\"\n    kernel_choices = [3, 5, 7]\n    depth_choices = [2, 3, 4]\n    n_stages = 5\n\n    def random_subnet():\n        return {\n            \u0027kernels\u0027: [random.choice(kernel_choices) for _ in range(n_stages)],\n            \u0027depths\u0027: [random.choice(depth_choices) for _ in range(n_stages)],\n        }\n\n    # Initialize population with valid (within budget) subnets\n    population = [c for _ in range(n_iterations)\n                  if (c := random_subnet()) and estimate_latency(c) \u003c= latency_budget_ms]\n\n    print(f\u0027Found {len(population)} valid subnets within {latency_budget_ms}ms budget\u0027)\n    if population:\n        lats = [estimate_latency(c) for c in population[:5]]\n        print(f\u0027Sample latencies (ms): {[round(l,2) for l in lats]}\u0027)\n    return population\n\nresults = evolutionary_subnet_search(n_iterations=200, latency_budget_ms=12.0)"},{"type":"heading","level":2,"content":"OFA Deployment — Mobile vs Server Subnet"},{"type":"text","content":"After training the OFA supernet once, selecting a subnet for a new hardware target takes minutes: measure the latency of individual operations on the target device, build a lookup table, run an evolutionary search over subnet configurations, and extract the best subnet. No gradient computation or weight updates are needed. The extracted subnet is evaluated by forward pass through the supernet with the fixed configuration."},{"type":"callout","variant":"tip","title":"OFA vs NAS-Retrain Trade-off","content":"Training the OFA supernet takes roughly 1200 GPU-hours — more than training a single EfficientNet. However, once trained, extracting and evaluating 10 subnets for 10 different hardware targets costs near zero. The break-even is approximately 3 hardware targets: if you are deploying to 3 or more devices, OFA\u0027s one-time training cost is offset by the elimination of repeated NAS runs."},{"type":"heading","level":2,"content":"Comparison with Competing Approaches"},{"type":"table","headers":["Method","Search Cost","Deployment Flexibility","Accuracy/Latency Pareto","Hardware Constraint Support","Retrain After Search"],"rows":[["MobileNetV3","~75 GPU-days (platform-specific)","Single target per search","Good (manually tuned)","Mobile-specific","N/A — fixed arch"],["DARTS","4 GPU-days","Single architecture","Moderate","No explicit constraint","Yes — re-train from scratch"],["ProxylessNAS/FBNet","~9 GPU-days per target","Single target per search","Very good","Latency table per device","No — fine-tune only"],["OFA","~1200 GPU-hours (one time)","Any subnet from 10^19 space","State of the art Pareto","Any device with LUT","No — direct extraction"],["EfficientNet-NAS","~3600 GPU-days","Fixed compound scale","State of art (single target)","Generic (TPU-tuned)","N/A — fixed arch"]]},{"type":"heading","level":2,"content":"Elastic Width — Channel Importance Sorting"},{"type":"text","content":"Elastic width means any subset of channels can be selected within each layer. For this to work with shared weights, channels must be sorted by importance before training. OFA sorts channels by their L1-norm of weights (most important first), then any subnet simply takes the top-k channels. This ordering is learned progressively during training: the network is periodically re-sorted after each elastic-width stage so that the first k channels always represent the best k channels for any k."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef sort_channels_by_importance(conv: nn.Conv2d, bn: nn.BatchNorm2d):\n    \"\"\"\n    Sort output channels by L1 norm of conv weights (descending).\n    Most important channels first so top-k slicing always gives best k.\n    Returns new conv and bn with reordered channels.\n    \"\"\"\n    import copy\n    W = conv.weight.data  # (C_out, C_in, kH, kW)\n    importance = W.abs().sum(dim=(1, 2, 3))  # (C_out,)\n    sorted_idx = importance.argsort(descending=True)  # most important first\n\n    new_conv = copy.deepcopy(conv)\n    new_conv.weight.data = W[sorted_idx]\n    if conv.bias is not None:\n        new_conv.bias.data = conv.bias.data[sorted_idx]\n\n    new_bn = copy.deepcopy(bn)\n    new_bn.weight.data = bn.weight.data[sorted_idx]\n    new_bn.bias.data = bn.bias.data[sorted_idx]\n    new_bn.running_mean = bn.running_mean[sorted_idx]\n    new_bn.running_var = bn.running_var[sorted_idx]\n\n    print(f\u0027Sorted {W.shape[0]} channels. Top-5 importance: \u0027\n          f\u0027{importance[sorted_idx[:5]].round(decimals=2).tolist()}\u0027)\n    return new_conv, new_bn\n\nconv = nn.Conv2d(3, 32, 3, padding=1)\nbn = nn.BatchNorm2d(32)\nnew_conv, new_bn = sort_channels_by_importance(conv, bn)\n# Now: new_conv.weight[:k] gives the best k output channels for any k\nfor k in [8, 16, 24, 32]:\n    sub_weight = new_conv.weight.data[:k]\n    print(f\u0027Top-{k} channels weight norm: {sub_weight.norm().item():.3f}\u0027)"},{"type":"text","content":"Accuracy results from the OFA paper (ImageNet): on a Pixel2 phone with a 58ms latency budget, OFA finds a subnet with 76.0% top-1 accuracy. MobileNetV3-Large with the same latency achieves 75.2%. On a Note10 GPU with a 12ms budget, OFA achieves 80.0% vs 79.8% for MobileNetV3. The accuracy gains are modest but the deployment flexibility (no NAS re-run) is the primary advantage."},{"type":"list","ordered":false,"items":["Progressive shrinking order: full → elastic kernel → elastic depth → elastic width (each stage adds one elastic dim).","In-place KD: teacher = same supernet at max config; student = random smaller config; no external teacher needed.","Elastic kernel transform matrix: learned linear map adapts 3×3 center crop from 7×7 weights — not just a slice.","Subnet accuracy proxy: train a small accuracy predictor (MLP on subnet config) to rank subnets without forward pass.","Resolution elasticity: training with random input crops [128,224] teaches the supernet to handle varying resolutions.","Deployment: subnet extraction is a forward pass with fixed config — takes milliseconds, no GPU gradient computation."]},{"type":"text","content":"The OFA accuracy predictor is a small MLP (3 layers, 400 hidden units) trained on (subnet_config → top-1_accuracy) pairs collected by sampling ~16,000 random subnets and evaluating them on a 10,000-image validation subset. Once trained, the predictor ranks subnets in microseconds, enabling evolutionary search over millions of candidates without any GPU forward passes. The predictor\u0027s ranking accuracy (Spearman correlation with true accuracy) is typically 0.95+, making it a reliable proxy for the full evaluation."},{"type":"divider"}]"
---
# Once-for-All — Train Once, Deploy Many Architectures

Standard NAS finds one architecture per hardware target. Deploying a model to 10 different devices (phone, tablet, server, IoT) requires 10 separate NAS runs, each potentially days of compute. Once-for-All (OFA, Cai et al. 2020) decouples training from search: a single supernet is trained once, and arbitrary subnets — defined by depth, width, kernel size, and resolution — can be extracted and deployed without any retraining. Each subnet achieves accuracy close to the equivalent standalone model.

## OFA Search Space

The OFA supernet is built from MobileNetV3-like inverted residual blocks. The elastic dimensions are: (1) kernel size per layer ∈ {3, 5, 7}, (2) depth (number of blocks per stage) ∈ {2, 3, 4}, (3) expand ratio (width multiplier inside blocks) ∈ {3, 4, 6}, and (4) input resolution ∈ {128, 160, 192, 224}. The total number of possible subnets exceeds 10^19, covering a continuous Pareto frontier from 150M to 600M FLOPs.

## Elastic Kernel Sharing

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class ElasticKernelConv(nn.Module):
    """
    A single conv weight of size 7x7 that can act as 7x7, 5x5, or 3x3
    by extracting the center sub-kernel (shared weights).
    """

    def __init__(self, in_channels: int, out_channels: int, max_kernel: int = 7):
        super().__init__()
        assert max_kernel in (7, 5, 3), 'max_kernel must be 7, 5, or 3'
        self.max_kernel = max_kernel
        # All kernel sizes share from this single weight tensor
        self.weight = nn.Parameter(
            torch.randn(out_channels, in_channels, max_kernel, max_kernel)
            * (2 / (in_channels * max_kernel ** 2)) ** 0.5
        )
        self.bias = nn.Parameter(torch.zeros(out_channels))
        # Learnable transformation matrices to adapt center kernel for smaller sizes
        self.transforms = nn.ParameterDict()
        for ks in [k for k in [3, 5, 7] if k < max_kernel]:
            self.transforms[str(ks)] = nn.Parameter(torch.eye(ks * ks))

    def _extract_sub_kernel(self, kernel_size: int) -> torch.Tensor:
        if kernel_size == self.max_kernel:
            return self.weight
        # Extract center crop
        start = (self.max_kernel - kernel_size) // 2
        sub = self.weight[:, :, start:start+kernel_size, start:start+kernel_size]
        # Apply learned linear transformation (shape-preserving)
        C_out, C_in = sub.shape[:2]
        sub_flat = sub.reshape(C_out * C_in, -1)  # (..., ks*ks)
        T = self.transforms[str(kernel_size)]      # (ks*ks, ks*ks)
        sub_transformed = (sub_flat @ T).reshape(C_out, C_in, kernel_size, kernel_size)
        return sub_transformed

    def forward(self, x: torch.Tensor, kernel_size: int = None) -> torch.Tensor:
        if kernel_size is None:
            kernel_size = self.max_kernel
        W = self._extract_sub_kernel(kernel_size)
        pad = kernel_size // 2
        return F.conv2d(x, W, self.bias, padding=pad)

# Demo: same weights, different kernel sizes
elastic_conv = ElasticKernelConv(16, 32, max_kernel=7)
x = torch.randn(2, 16, 8, 8)
for ks in [3, 5, 7]:
    out = elastic_conv(x, kernel_size=ks)
    print(f'kernel_size={ks}: input {x.shape} -> output {out.shape}')
```

## Progressive Shrinking Training

Training the full supernet from scratch is difficult: all subnets share weights, and small subnets interfere with large ones. Progressive shrinking solves this by training in stages: (1) train the full network (largest kernel, most layers, widest expand ratio) to convergence; (2) add elastic kernel by training with randomly sampled kernel sizes while distilling from the full-kernel subnet; (3) add elastic depth by randomly dropping layers; (4) add elastic width. Each stage uses in-place knowledge distillation: the teacher is the same supernet evaluated with the current stage's maximum configuration.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import random

def progressive_shrinking_step(supernet, x, y_true, criterion,
                               stage='kernel',
                               kernel_choices=(3, 5, 7),
                               depth_choices=(2, 3, 4)):
    """
    One training step with progressive shrinking and in-place distillation.
    Teacher: supernet with max config. Student: random smaller config.
    """
    supernet.eval()
    # Teacher forward: always max config
    with torch.no_grad():
        teacher_logits = supernet(x, kernel_size=max(kernel_choices),
                                  depth=max(depth_choices))
        teacher_probs = F.softmax(teacher_logits / 4.0, dim=-1)  # T=4 temperature

    supernet.train()
    # Student forward: random smaller config
    if stage == 'kernel':
        ks = random.choice(kernel_choices)
        student_logits = supernet(x, kernel_size=ks, depth=max(depth_choices))
    elif stage == 'depth':
        ks = random.choice(kernel_choices)
        d = random.choice(depth_choices)
        student_logits = supernet(x, kernel_size=ks, depth=d)
    else:
        student_logits = supernet(x, kernel_size=max(kernel_choices),
                                  depth=max(depth_choices))

    # Combined loss: task loss + KD loss from teacher
    task_loss = criterion(student_logits, y_true)
    kd_loss = F.kl_div(
        F.log_softmax(student_logits / 4.0, dim=-1),
        teacher_probs,
        reduction='batchmean'
    ) * (4.0 ** 2)  # scale by T^2

    total_loss = 0.5 * task_loss + 0.5 * kd_loss
    return total_loss, task_loss.item(), kd_loss.item()

print('Progressive shrinking: full -> elastic kernel -> elastic depth -> elastic width')
```

## Subnet Search with Latency Lookup

```python
import torch
import random
from itertools import product

# Precomputed latency lookup table (ms) for each op on target device
# In practice, measured by profiling each op independently
LATENCY_LUT = {
    ('conv3', 2): 1.2, ('conv3', 3): 1.8, ('conv3', 4): 2.4,
    ('conv5', 2): 2.1, ('conv5', 3): 3.2, ('conv5', 4): 4.3,
    ('conv7', 2): 3.5, ('conv7', 3): 5.2, ('conv7', 4): 6.9,
}

def estimate_latency(subnet_config: dict) -> float:
    """Estimate latency from lookup table without running the model."""
    total = 0.0
    for stage_idx, (kernel, depth) in enumerate(
        zip(subnet_config['kernels'], subnet_config['depths'])
    ):
        key = (f'conv{kernel}', depth)
        total += LATENCY_LUT.get(key, 3.0)  # default 3ms if not in table
    return total

def evolutionary_subnet_search(n_iterations=100, latency_budget_ms=12.0,
                               population_size=50):
    """Simple evolutionary search over subnet configurations."""
    kernel_choices = [3, 5, 7]
    depth_choices = [2, 3, 4]
    n_stages = 5

    def random_subnet():
        return {
            'kernels': [random.choice(kernel_choices) for _ in range(n_stages)],
            'depths': [random.choice(depth_choices) for _ in range(n_stages)],
        }

    # Initialize population with valid (within budget) subnets
    population = [c for _ in range(n_iterations)
                  if (c := random_subnet()) and estimate_latency(c) <= latency_budget_ms]

    print(f'Found {len(population)} valid subnets within {latency_budget_ms}ms budget')
    if population:
        lats = [estimate_latency(c) for c in population[:5]]
        print(f'Sample latencies (ms): {[round(l,2) for l in lats]}')
    return population

results = evolutionary_subnet_search(n_iterations=200, latency_budget_ms=12.0)
```

## OFA Deployment — Mobile vs Server Subnet

After training the OFA supernet once, selecting a subnet for a new hardware target takes minutes: measure the latency of individual operations on the target device, build a lookup table, run an evolutionary search over subnet configurations, and extract the best subnet. No gradient computation or weight updates are needed. The extracted subnet is evaluated by forward pass through the supernet with the fixed configuration.

> **OFA vs NAS-Retrain Trade-off**: Training the OFA supernet takes roughly 1200 GPU-hours — more than training a single EfficientNet. However, once trained, extracting and evaluating 10 subnets for 10 different hardware targets costs near zero. The break-even is approximately 3 hardware targets: if you are deploying to 3 or more devices, OFA's one-time training cost is offset by the elimination of repeated NAS runs.

## Comparison with Competing Approaches

| Method | Search Cost | Deployment Flexibility | Accuracy/Latency Pareto | Hardware Constraint Support | Retrain After Search |
| --- | --- | --- | --- | --- | --- |
| MobileNetV3 | ~75 GPU-days (platform-specific) | Single target per search | Good (manually tuned) | Mobile-specific | N/A — fixed arch |
| DARTS | 4 GPU-days | Single architecture | Moderate | No explicit constraint | Yes — re-train from scratch |
| ProxylessNAS/FBNet | ~9 GPU-days per target | Single target per search | Very good | Latency table per device | No — fine-tune only |
| OFA | ~1200 GPU-hours (one time) | Any subnet from 10^19 space | State of the art Pareto | Any device with LUT | No — direct extraction |
| EfficientNet-NAS | ~3600 GPU-days | Fixed compound scale | State of art (single target) | Generic (TPU-tuned) | N/A — fixed arch |

## Elastic Width — Channel Importance Sorting

Elastic width means any subset of channels can be selected within each layer. For this to work with shared weights, channels must be sorted by importance before training. OFA sorts channels by their L1-norm of weights (most important first), then any subnet simply takes the top-k channels. This ordering is learned progressively during training: the network is periodically re-sorted after each elastic-width stage so that the first k channels always represent the best k channels for any k.

```python
import torch
import torch.nn as nn

def sort_channels_by_importance(conv: nn.Conv2d, bn: nn.BatchNorm2d):
    """
    Sort output channels by L1 norm of conv weights (descending).
    Most important channels first so top-k slicing always gives best k.
    Returns new conv and bn with reordered channels.
    """
    import copy
    W = conv.weight.data  # (C_out, C_in, kH, kW)
    importance = W.abs().sum(dim=(1, 2, 3))  # (C_out,)
    sorted_idx = importance.argsort(descending=True)  # most important first

    new_conv = copy.deepcopy(conv)
    new_conv.weight.data = W[sorted_idx]
    if conv.bias is not None:
        new_conv.bias.data = conv.bias.data[sorted_idx]

    new_bn = copy.deepcopy(bn)
    new_bn.weight.data = bn.weight.data[sorted_idx]
    new_bn.bias.data = bn.bias.data[sorted_idx]
    new_bn.running_mean = bn.running_mean[sorted_idx]
    new_bn.running_var = bn.running_var[sorted_idx]

    print(f'Sorted {W.shape[0]} channels. Top-5 importance: '
          f'{importance[sorted_idx[:5]].round(decimals=2).tolist()}')
    return new_conv, new_bn

conv = nn.Conv2d(3, 32, 3, padding=1)
bn = nn.BatchNorm2d(32)
new_conv, new_bn = sort_channels_by_importance(conv, bn)
# Now: new_conv.weight[:k] gives the best k output channels for any k
for k in [8, 16, 24, 32]:
    sub_weight = new_conv.weight.data[:k]
    print(f'Top-{k} channels weight norm: {sub_weight.norm().item():.3f}')
```

Accuracy results from the OFA paper (ImageNet): on a Pixel2 phone with a 58ms latency budget, OFA finds a subnet with 76.0% top-1 accuracy. MobileNetV3-Large with the same latency achieves 75.2%. On a Note10 GPU with a 12ms budget, OFA achieves 80.0% vs 79.8% for MobileNetV3. The accuracy gains are modest but the deployment flexibility (no NAS re-run) is the primary advantage.

- Progressive shrinking order: full → elastic kernel → elastic depth → elastic width (each stage adds one elastic dim).
- In-place KD: teacher = same supernet at max config; student = random smaller config; no external teacher needed.
- Elastic kernel transform matrix: learned linear map adapts 3×3 center crop from 7×7 weights — not just a slice.
- Subnet accuracy proxy: train a small accuracy predictor (MLP on subnet config) to rank subnets without forward pass.
- Resolution elasticity: training with random input crops [128,224] teaches the supernet to handle varying resolutions.
- Deployment: subnet extraction is a forward pass with fixed config — takes milliseconds, no GPU gradient computation.

The OFA accuracy predictor is a small MLP (3 layers, 400 hidden units) trained on (subnet_config → top-1_accuracy) pairs collected by sampling ~16,000 random subnets and evaluating them on a 10,000-image validation subset. Once trained, the predictor ranks subnets in microseconds, enabling evolutionary search over millions of candidates without any GPU forward passes. The predictor's ranking accuracy (Spearman correlation with true accuracy) is typically 0.95+, making it a reliable proxy for the full evaluation.

---

