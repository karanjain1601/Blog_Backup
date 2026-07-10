---
title: "NAS — Differentiable Architecture Search and Efficiency Proxies"
slug: "nas-neural-architecture-search"
description: "Neural architecture search from RL-based controllers to DARTS bi-level optimization. Covers the search space definition, differentiable relaxation, efficiency-aware objectives (FLOPs, latency), and one-shot supernet methods with weight sharing."
tags: ["deep-learning", "model-compression", "pruning", "quantization"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Neural architecture search (NAS) automates the design of neural network architectures by formulating architecture selection as an optimization problem. Early NAS methods used reinforcement learning to train a controller that proposes architectures, evaluated each on a proxy task, and updated the controller based on the validation accuracy. This required thousands of GPU-hours and hundreds of GPU machines. Modern NAS methods — DARTS, one-shot supernets, and efficiency-aware search — have reduced the cost to a single GPU-day or less."},{"type":"heading","level":2,"content":"Search Space Definition"},{"type":"text","content":"The search space determines which architectures can be found. A typical cell-based search space defines a computational cell (a small graph of operations) and stacks N cells to form the full network. At each edge in the cell, the operation is chosen from a candidate set: 3×3 conv, 5×5 conv, 3×3 dilated conv, 3×3 max pool, skip connection, zero. With 7 candidate ops and 14 edges in a cell, the search space has 7^14 ≈ 10^12 possible cells. RL-NAS samples directly from this space; DARTS relaxes it to a continuous mixture."},{"type":"heading","level":2,"content":"DARTS — Differentiable Mixed Operation"},{"type":"text","content":"DARTS (Liu et al. 2019) relaxes the discrete operation selection to a continuous mixture: for each edge, the output is a weighted sum of all candidate operations: ō(x) = Σ_i exp(α_i) / Σ_j exp(α_j) · o_i(x). The architecture parameters α (one per operation per edge) are learned jointly with the weight parameters w by gradient descent. After search, the architecture is discretized by selecting the highest-α operation on each edge."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass MixedOp(nn.Module):\n    \"\"\"DARTS mixed operation: weighted softmax mixture of candidate ops.\"\"\"\n\n    CANDIDATES = {\n        \u0027skip\u0027: lambda C: nn.Identity(),\n        \u0027conv3x3\u0027: lambda C: nn.Sequential(nn.Conv2d(C, C, 3, padding=1, bias=False), nn.BatchNorm2d(C)),\n        \u0027conv5x5\u0027: lambda C: nn.Sequential(nn.Conv2d(C, C, 5, padding=2, bias=False), nn.BatchNorm2d(C)),\n        \u0027maxpool\u0027: lambda C: nn.MaxPool2d(3, stride=1, padding=1),\n        \u0027avgpool\u0027: lambda C: nn.AvgPool2d(3, stride=1, padding=1),\n    }\n\n    def __init__(self, C: int):\n        super().__init__()\n        self.ops = nn.ModuleList([fn(C) for fn in self.CANDIDATES.values()])\n        self.op_names = list(self.CANDIDATES.keys())\n        # Architecture weights (α) — not in model.parameters(), trained separately\n        self.arch_weights = nn.Parameter(torch.zeros(len(self.ops)))\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        weights = F.softmax(self.arch_weights, dim=0)\n        return sum(w * op(x) for w, op in zip(weights, self.ops))\n\n    def discretize(self) -\u003e str:\n        \"\"\"Return the name of the operation with highest arch weight.\"\"\"\n        best = self.arch_weights.argmax().item()\n        return self.op_names[best]\n\n# Demo\nC = 16\nmixed = MixedOp(C)\nx = torch.randn(2, C, 8, 8)\nout = mixed(x)\nprint(f\u0027Output shape: {out.shape}\u0027)\nprint(f\u0027Arch weights (softmax): {F.softmax(mixed.arch_weights, dim=0).detach().round(decimals=3).tolist()}\u0027)\nprint(f\u0027Discretized operation: {mixed.discretize()}\u0027)"},{"type":"heading","level":2,"content":"DARTS Bi-Level Optimization"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\n\ndef darts_train_step(model, arch_params, train_batch, val_batch, criterion,\n                     w_optimizer, arch_optimizer, inner_steps=1):\n    \"\"\"\n    DARTS alternating optimization:\n    1. Update architecture params alpha on validation loss.\n    2. Update weight params w on training loss.\n    \"\"\"\n    X_train, y_train = train_batch\n    X_val, y_val = val_batch\n\n    # Step 1: Update architecture parameters on validation set\n    arch_optimizer.zero_grad()\n    val_loss = criterion(model(X_val), y_val)\n    val_loss.backward()\n    arch_optimizer.step()\n\n    # Step 2: Update weight parameters on training set\n    for _ in range(inner_steps):\n        w_optimizer.zero_grad()\n        train_loss = criterion(model(X_train), y_train)\n        train_loss.backward()\n        w_optimizer.step()\n\n    return train_loss.item(), val_loss.item()\n\n# Separate weight and arch parameters for dual optimizers\n# (arch_params have requires_grad=True and are passed to arch_optimizer)\nprint(\u0027DARTS bi-level: arch optimizer -\u003e val loss; weight optimizer -\u003e train loss\u0027)\nprint(\u0027After search: discretize by argmax(arch_weights) per edge.\u0027)\nprint(\u0027Re-train discretized architecture from scratch for fair comparison.\u0027)"},{"type":"heading","level":2,"content":"Efficiency-Aware NAS"},{"type":"text","content":"Accuracy alone is insufficient for mobile and edge deployment. Efficiency-aware NAS adds a hardware cost term to the objective: L_total = L_CE(y, ŷ) + λ · log(latency(α)). The latency is estimated from a lookup table (op × resolution × hardware) rather than measured at every step. FBNet and ProxylessNAS use this approach. The λ hyperparameter controls the accuracy-latency trade-off; sweeping λ produces a Pareto frontier of architectures."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\n# Latency lookup table: op -\u003e (ms on mobile CPU, ms on server GPU)\nLATENCY_TABLE = {\n    \u0027skip\u0027:    (0.05, 0.01),\n    \u0027conv3x3\u0027: (1.20, 0.15),\n    \u0027conv5x5\u0027: (2.80, 0.30),\n    \u0027maxpool\u0027: (0.30, 0.04),\n    \u0027avgpool\u0027: (0.25, 0.04),\n}\n\ndef differentiable_latency(arch_weights: torch.Tensor,\n                           op_names: list,\n                           target: str = \u0027mobile\u0027) -\u003e torch.Tensor:\n    \"\"\"\n    Expected latency as a differentiable function of arch weights.\n    target: \u0027mobile\u0027 (index 0) or \u0027server\u0027 (index 1)\n    \"\"\"\n    idx = 0 if target == \u0027mobile\u0027 else 1\n    lat_tensor = torch.tensor(\n        [LATENCY_TABLE[name][idx] for name in op_names],\n        dtype=torch.float32\n    )\n    probs = torch.softmax(arch_weights, dim=0)\n    return (probs * lat_tensor).sum()  # expected latency\n\ndef efficiency_aware_loss(task_loss, arch_weights, op_names, lam=0.1, target=\u0027mobile\u0027):\n    lat = differentiable_latency(arch_weights, op_names, target)\n    return task_loss + lam * torch.log(lat + 1e-6)\n\n# Demo\narch_w = torch.randn(5, requires_grad=True)\nop_names = list(LATENCY_TABLE.keys())\ntask_loss = torch.tensor(1.5)\ntotal_loss = efficiency_aware_loss(task_loss, arch_w, op_names, lam=0.1)\ntotal_loss.backward()\nprint(f\u0027Total loss: {total_loss.item():.4f}\u0027)\nprint(f\u0027arch_w grad: {arch_w.grad.round(decimals=4).tolist()}\u0027)"},{"type":"heading","level":2,"content":"One-Shot Supernet with Weight Sharing"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport random\n\nclass Supernet(nn.Module):\n    \"\"\"One-shot supernet: all subnets share the same weights.\"\"\"\n\n    OPS = [\u0027skip\u0027, \u0027conv3\u0027, \u0027conv5\u0027, \u0027pool\u0027]\n\n    def __init__(self, n_layers: int = 4, C: int = 32):\n        super().__init__()\n        self.n_layers = n_layers\n        self.layers = nn.ModuleList([\n            nn.ModuleDict({\n                \u0027skip\u0027:  nn.Identity(),\n                \u0027conv3\u0027: nn.Sequential(nn.Conv2d(C, C, 3, padding=1), nn.ReLU()),\n                \u0027conv5\u0027: nn.Sequential(nn.Conv2d(C, C, 5, padding=2), nn.ReLU()),\n                \u0027pool\u0027:  nn.AvgPool2d(3, stride=1, padding=1),\n            })\n            for _ in range(n_layers)\n        ])\n        self.classifier = nn.AdaptiveAvgPool2d(1)\n\n    def forward(self, x: torch.Tensor, subnet: list = None) -\u003e torch.Tensor:\n        \"\"\"subnet: list of op names per layer. If None, sample randomly.\"\"\"\n        if subnet is None:\n            subnet = [random.choice(self.OPS) for _ in range(self.n_layers)]\n        for op_choice, layer_ops in zip(subnet, self.layers):\n            x = layer_ops[op_choice](x)\n        return self.classifier(x).squeeze(-1).squeeze(-1)\n\n# Train supernet with random subnet sampling\nsupernet = Supernet(n_layers=4, C=32)\nx = torch.randn(4, 32, 8, 8)\n# Each forward uses a different random subnet -\u003e all op weights get trained\nfor step in range(3):\n    subnet = [random.choice(Supernet.OPS) for _ in range(4)]\n    out = supernet(x, subnet)\n    print(f\u0027Step {step+1} subnet={subnet}  out.shape={out.shape}\u0027)"},{"type":"callout","variant":"info","title":"Weight Coupling in One-Shot NAS","content":"In a one-shot supernet, all subnets share weights. This causes weight coupling: the optimal weights for the conv3 subnet are not the same as the optimal weights when conv3 coexists with conv5. This coupling means the supernet ranking of subnets does not perfectly correlate with their standalone accuracy after retraining. Once-for-All (OFA) addresses this with progressive shrinking and in-place distillation."},{"type":"heading","level":2,"content":"NAS Method Comparison"},{"type":"table","headers":["Method","GPU-Days (Search)","Search Type","Top-1 ImageNet","FLOP Efficiency","Target Hardware"],"rows":[["RL-NAS (Zoph 2017)","~1800 GPU-days","Discrete sampling via RL controller","74.0%","Not optimized","Generic"],["DARTS (2019)","~4 GPU-days","Continuous relaxation, gradient","73.3%","Not optimized","Generic"],["FBNet (2019)","~9 GPU-days","Gumbel-softmax + latency table","74.9%","Mobile (50M FLOPs)","Mobile CPU"],["One-shot (SNAS)","~1.5 GPU-days","Weight sharing + stochastic sampling","72.7%","Moderate","Generic"],["EfficientNet (manual+NAS)","~N/A (compound)","Grid search over depth/width/res","84.4%","Excellent Pareto","All hardware"]]},{"type":"heading","level":2,"content":"DARTS Pitfalls and Fixes"},{"type":"text","content":"DARTS has known failure modes. The bi-level optimization is only an approximation: the inner optimization (weight update) is not taken to convergence, so the architecture gradient is biased. This can cause the search to over-select skip connections (zero-parameter, low-loss operations), collapsing the architecture to a near-identity mapping. Fixes include DARTS+ (regularize skip count), GDAS (Gumbel-softmax with temperature annealing), and SNAS (stochastic NAS with KL divergence constraints)."},{"type":"text","content":"A practical DARTS training schedule: search for 50 epochs with architecture LR 3e-4 and weight LR 3e-4; keep a strict 50/50 train/val split so architecture gradients are not computed on training data; after search, discretize and re-train the discovered architecture from scratch for 600 epochs. The re-training step is important — accuracy measured on the mixed operation supernet is not representative of the discretized architecture."},{"type":"list","ordered":false,"items":["Skip connection collapse: DARTS tends to select skip connections — force at most 2 skips per cell.","Bi-level approximation bias: use first-order DARTS (ignore second-order Hessian) for stability at slight accuracy cost.","Discretize then retrain: the supernet accuracy is not the final model accuracy — always retrain from scratch.","Proxy task: search on a small proxy (CIFAR-10) then transfer architecture to the target dataset.","Early stopping of arch search: over-searching degrades the architecture — 50 epochs is usually enough.","One-shot vs DARTS: one-shot avoids bi-level entirely by training a supernet and sampling subnets."]},{"type":"text","content":"Efficiency proxies beyond latency tables include FLOPs, number of parameters, and energy consumption. FLOPs is hardware-agnostic but does not account for memory bandwidth — a depthwise conv has far fewer FLOPs than a standard conv but is memory-bandwidth-bound on GPU. Latency lookup tables measured on the actual target device are more accurate proxies, especially for mobile CPU vs GPU vs DSP."},{"type":"list","ordered":false,"items":["FLOPs: easy to compute analytically but poor predictor of GPU latency (memory-bound operations are penalised unfairly).","Latency LUT: measure each (op, resolution, channel) combination on target device; fast to query during search.","Energy: critical for battery-powered devices; correlates with memory access count more than FLOPs.","Model size (MB): important for over-the-air update and on-device storage, not for inference speed.","Hardware-aware NAS: ProxylessNAS, FBNet, MNASNet — all use hardware-specific latency models."]},{"type":"divider"}]"
---
# NAS — Differentiable Architecture Search and Efficiency Proxies

Neural architecture search (NAS) automates the design of neural network architectures by formulating architecture selection as an optimization problem. Early NAS methods used reinforcement learning to train a controller that proposes architectures, evaluated each on a proxy task, and updated the controller based on the validation accuracy. This required thousands of GPU-hours and hundreds of GPU machines. Modern NAS methods — DARTS, one-shot supernets, and efficiency-aware search — have reduced the cost to a single GPU-day or less.

## Search Space Definition

The search space determines which architectures can be found. A typical cell-based search space defines a computational cell (a small graph of operations) and stacks N cells to form the full network. At each edge in the cell, the operation is chosen from a candidate set: 3×3 conv, 5×5 conv, 3×3 dilated conv, 3×3 max pool, skip connection, zero. With 7 candidate ops and 14 edges in a cell, the search space has 7^14 ≈ 10^12 possible cells. RL-NAS samples directly from this space; DARTS relaxes it to a continuous mixture.

## DARTS — Differentiable Mixed Operation

DARTS (Liu et al. 2019) relaxes the discrete operation selection to a continuous mixture: for each edge, the output is a weighted sum of all candidate operations: ō(x) = Σ_i exp(α_i) / Σ_j exp(α_j) · o_i(x). The architecture parameters α (one per operation per edge) are learned jointly with the weight parameters w by gradient descent. After search, the architecture is discretized by selecting the highest-α operation on each edge.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class MixedOp(nn.Module):
    """DARTS mixed operation: weighted softmax mixture of candidate ops."""

    CANDIDATES = {
        'skip': lambda C: nn.Identity(),
        'conv3x3': lambda C: nn.Sequential(nn.Conv2d(C, C, 3, padding=1, bias=False), nn.BatchNorm2d(C)),
        'conv5x5': lambda C: nn.Sequential(nn.Conv2d(C, C, 5, padding=2, bias=False), nn.BatchNorm2d(C)),
        'maxpool': lambda C: nn.MaxPool2d(3, stride=1, padding=1),
        'avgpool': lambda C: nn.AvgPool2d(3, stride=1, padding=1),
    }

    def __init__(self, C: int):
        super().__init__()
        self.ops = nn.ModuleList([fn(C) for fn in self.CANDIDATES.values()])
        self.op_names = list(self.CANDIDATES.keys())
        # Architecture weights (α) — not in model.parameters(), trained separately
        self.arch_weights = nn.Parameter(torch.zeros(len(self.ops)))

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        weights = F.softmax(self.arch_weights, dim=0)
        return sum(w * op(x) for w, op in zip(weights, self.ops))

    def discretize(self) -> str:
        """Return the name of the operation with highest arch weight."""
        best = self.arch_weights.argmax().item()
        return self.op_names[best]

# Demo
C = 16
mixed = MixedOp(C)
x = torch.randn(2, C, 8, 8)
out = mixed(x)
print(f'Output shape: {out.shape}')
print(f'Arch weights (softmax): {F.softmax(mixed.arch_weights, dim=0).detach().round(decimals=3).tolist()}')
print(f'Discretized operation: {mixed.discretize()}')
```

## DARTS Bi-Level Optimization

```python
import torch
import torch.nn as nn
import torch.optim as optim

def darts_train_step(model, arch_params, train_batch, val_batch, criterion,
                     w_optimizer, arch_optimizer, inner_steps=1):
    """
    DARTS alternating optimization:
    1. Update architecture params alpha on validation loss.
    2. Update weight params w on training loss.
    """
    X_train, y_train = train_batch
    X_val, y_val = val_batch

    # Step 1: Update architecture parameters on validation set
    arch_optimizer.zero_grad()
    val_loss = criterion(model(X_val), y_val)
    val_loss.backward()
    arch_optimizer.step()

    # Step 2: Update weight parameters on training set
    for _ in range(inner_steps):
        w_optimizer.zero_grad()
        train_loss = criterion(model(X_train), y_train)
        train_loss.backward()
        w_optimizer.step()

    return train_loss.item(), val_loss.item()

# Separate weight and arch parameters for dual optimizers
# (arch_params have requires_grad=True and are passed to arch_optimizer)
print('DARTS bi-level: arch optimizer -> val loss; weight optimizer -> train loss')
print('After search: discretize by argmax(arch_weights) per edge.')
print('Re-train discretized architecture from scratch for fair comparison.')
```

## Efficiency-Aware NAS

Accuracy alone is insufficient for mobile and edge deployment. Efficiency-aware NAS adds a hardware cost term to the objective: L_total = L_CE(y, ŷ) + λ · log(latency(α)). The latency is estimated from a lookup table (op × resolution × hardware) rather than measured at every step. FBNet and ProxylessNAS use this approach. The λ hyperparameter controls the accuracy-latency trade-off; sweeping λ produces a Pareto frontier of architectures.

```python
import torch
import torch.nn as nn

# Latency lookup table: op -> (ms on mobile CPU, ms on server GPU)
LATENCY_TABLE = {
    'skip':    (0.05, 0.01),
    'conv3x3': (1.20, 0.15),
    'conv5x5': (2.80, 0.30),
    'maxpool': (0.30, 0.04),
    'avgpool': (0.25, 0.04),
}

def differentiable_latency(arch_weights: torch.Tensor,
                           op_names: list,
                           target: str = 'mobile') -> torch.Tensor:
    """
    Expected latency as a differentiable function of arch weights.
    target: 'mobile' (index 0) or 'server' (index 1)
    """
    idx = 0 if target == 'mobile' else 1
    lat_tensor = torch.tensor(
        [LATENCY_TABLE[name][idx] for name in op_names],
        dtype=torch.float32
    )
    probs = torch.softmax(arch_weights, dim=0)
    return (probs * lat_tensor).sum()  # expected latency

def efficiency_aware_loss(task_loss, arch_weights, op_names, lam=0.1, target='mobile'):
    lat = differentiable_latency(arch_weights, op_names, target)
    return task_loss + lam * torch.log(lat + 1e-6)

# Demo
arch_w = torch.randn(5, requires_grad=True)
op_names = list(LATENCY_TABLE.keys())
task_loss = torch.tensor(1.5)
total_loss = efficiency_aware_loss(task_loss, arch_w, op_names, lam=0.1)
total_loss.backward()
print(f'Total loss: {total_loss.item():.4f}')
print(f'arch_w grad: {arch_w.grad.round(decimals=4).tolist()}')
```

## One-Shot Supernet with Weight Sharing

```python
import torch
import torch.nn as nn
import random

class Supernet(nn.Module):
    """One-shot supernet: all subnets share the same weights."""

    OPS = ['skip', 'conv3', 'conv5', 'pool']

    def __init__(self, n_layers: int = 4, C: int = 32):
        super().__init__()
        self.n_layers = n_layers
        self.layers = nn.ModuleList([
            nn.ModuleDict({
                'skip':  nn.Identity(),
                'conv3': nn.Sequential(nn.Conv2d(C, C, 3, padding=1), nn.ReLU()),
                'conv5': nn.Sequential(nn.Conv2d(C, C, 5, padding=2), nn.ReLU()),
                'pool':  nn.AvgPool2d(3, stride=1, padding=1),
            })
            for _ in range(n_layers)
        ])
        self.classifier = nn.AdaptiveAvgPool2d(1)

    def forward(self, x: torch.Tensor, subnet: list = None) -> torch.Tensor:
        """subnet: list of op names per layer. If None, sample randomly."""
        if subnet is None:
            subnet = [random.choice(self.OPS) for _ in range(self.n_layers)]
        for op_choice, layer_ops in zip(subnet, self.layers):
            x = layer_ops[op_choice](x)
        return self.classifier(x).squeeze(-1).squeeze(-1)

# Train supernet with random subnet sampling
supernet = Supernet(n_layers=4, C=32)
x = torch.randn(4, 32, 8, 8)
# Each forward uses a different random subnet -> all op weights get trained
for step in range(3):
    subnet = [random.choice(Supernet.OPS) for _ in range(4)]
    out = supernet(x, subnet)
    print(f'Step {step+1} subnet={subnet}  out.shape={out.shape}')
```

> **Weight Coupling in One-Shot NAS**: In a one-shot supernet, all subnets share weights. This causes weight coupling: the optimal weights for the conv3 subnet are not the same as the optimal weights when conv3 coexists with conv5. This coupling means the supernet ranking of subnets does not perfectly correlate with their standalone accuracy after retraining. Once-for-All (OFA) addresses this with progressive shrinking and in-place distillation.

## NAS Method Comparison

| Method | GPU-Days (Search) | Search Type | Top-1 ImageNet | FLOP Efficiency | Target Hardware |
| --- | --- | --- | --- | --- | --- |
| RL-NAS (Zoph 2017) | ~1800 GPU-days | Discrete sampling via RL controller | 74.0% | Not optimized | Generic |
| DARTS (2019) | ~4 GPU-days | Continuous relaxation, gradient | 73.3% | Not optimized | Generic |
| FBNet (2019) | ~9 GPU-days | Gumbel-softmax + latency table | 74.9% | Mobile (50M FLOPs) | Mobile CPU |
| One-shot (SNAS) | ~1.5 GPU-days | Weight sharing + stochastic sampling | 72.7% | Moderate | Generic |
| EfficientNet (manual+NAS) | ~N/A (compound) | Grid search over depth/width/res | 84.4% | Excellent Pareto | All hardware |

## DARTS Pitfalls and Fixes

DARTS has known failure modes. The bi-level optimization is only an approximation: the inner optimization (weight update) is not taken to convergence, so the architecture gradient is biased. This can cause the search to over-select skip connections (zero-parameter, low-loss operations), collapsing the architecture to a near-identity mapping. Fixes include DARTS+ (regularize skip count), GDAS (Gumbel-softmax with temperature annealing), and SNAS (stochastic NAS with KL divergence constraints).

A practical DARTS training schedule: search for 50 epochs with architecture LR 3e-4 and weight LR 3e-4; keep a strict 50/50 train/val split so architecture gradients are not computed on training data; after search, discretize and re-train the discovered architecture from scratch for 600 epochs. The re-training step is important — accuracy measured on the mixed operation supernet is not representative of the discretized architecture.

- Skip connection collapse: DARTS tends to select skip connections — force at most 2 skips per cell.
- Bi-level approximation bias: use first-order DARTS (ignore second-order Hessian) for stability at slight accuracy cost.
- Discretize then retrain: the supernet accuracy is not the final model accuracy — always retrain from scratch.
- Proxy task: search on a small proxy (CIFAR-10) then transfer architecture to the target dataset.
- Early stopping of arch search: over-searching degrades the architecture — 50 epochs is usually enough.
- One-shot vs DARTS: one-shot avoids bi-level entirely by training a supernet and sampling subnets.

Efficiency proxies beyond latency tables include FLOPs, number of parameters, and energy consumption. FLOPs is hardware-agnostic but does not account for memory bandwidth — a depthwise conv has far fewer FLOPs than a standard conv but is memory-bandwidth-bound on GPU. Latency lookup tables measured on the actual target device are more accurate proxies, especially for mobile CPU vs GPU vs DSP.

- FLOPs: easy to compute analytically but poor predictor of GPU latency (memory-bound operations are penalised unfairly).
- Latency LUT: measure each (op, resolution, channel) combination on target device; fast to query during search.
- Energy: critical for battery-powered devices; correlates with memory access count more than FLOPs.
- Model size (MB): important for over-the-air update and on-device storage, not for inference speed.
- Hardware-aware NAS: ProxylessNAS, FBNet, MNASNet — all use hardware-specific latency models.

---

