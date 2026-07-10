---
title: "Movement Pruning — Learning Which Weights to Prune"
slug: "movement-pruning"
description: "Movement pruning (Sanh et al. 2020) trains importance scores via gradient descent, pruning weights that move toward zero during fine-tuning. Covers score initialization, straight-through estimator, soft movement pruning, and comparison with magnitude and gradient-based criteria for BERT."
tags: ["deep-learning", "model-compression", "pruning", "quantization"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Magnitude pruning removes the smallest weights by absolute value. This works well for models trained from scratch but is poorly suited to fine-tuned models: during task-specific fine-tuning, the weights that matter most for the task may be small in magnitude but moving strongly away from zero, while large pre-trained weights that are irrelevant to the task remain large but become unimportant. Movement pruning addresses this by pruning weights that move toward zero during fine-tuning, learning which weights to keep jointly with the task objective."},{"type":"heading","level":2,"content":"The Movement Pruning Objective"},{"type":"text","content":"Movement pruning (Sanh et al. 2020) introduces a real-valued score S_i for each weight W_i, initialized to zero. During training, a binary mask is derived by keeping the top-k weights by score: M = top-k(|S|). The forward pass uses W ⊙ M (masked weights). The gradient of the task loss ∂L/∂S flows through the straight-through estimator, allowing the scores to be trained even though the masking operation is discrete. A positive score gradient means the weight is becoming more important; a negative gradient drives the score toward zero, eventually pruning the weight."},{"type":"heading","level":2,"content":"Score Computation and Mask Generation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass MovementPruningLinear(nn.Module):\n    \"\"\"Linear layer with learnable movement pruning scores.\"\"\"\n\n    def __init__(self, in_features: int, out_features: int, sparsity: float = 0.8):\n        super().__init__()\n        self.weight = nn.Parameter(torch.randn(out_features, in_features) * 0.02)\n        self.bias = nn.Parameter(torch.zeros(out_features))\n        self.scores = nn.Parameter(torch.zeros_like(self.weight))  # S_i = 0 initially\n        self.sparsity = sparsity\n\n    def _get_mask(self) -\u003e torch.Tensor:\n        n_keep = max(1, int(self.weight.numel() * (1 - self.sparsity)))\n        # Top-k by absolute score value\n        threshold = self.scores.abs().flatten().topk(n_keep).values.min()\n        return (self.scores.abs() \u003e= threshold).float()\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        mask = self._get_mask()  # binary, non-differentiable\n        masked_weight = self.weight * mask  # scores gradient via STE (see next block)\n        return nn.functional.linear(x, masked_weight, self.bias)\n\n# Verify score shapes\nlayer = MovementPruningLinear(128, 64, sparsity=0.8)\nx = torch.randn(8, 128)\nout = layer(x)\nprint(f\u0027Output shape: {out.shape}\u0027)\nprint(f\u0027Score shape: {layer.scores.shape}\u0027)\nprint(f\u0027Active weights: {layer._get_mask().sum().item():.0f}/{layer.weight.numel()}\u0027)"},{"type":"heading","level":2,"content":"Straight-Through Estimator for Discrete Masks"},{"type":"text","content":"The top-k masking operation has zero gradient almost everywhere. The straight-through estimator (STE) bypasses this by passing the upstream gradient through the masking operation unchanged during the backward pass: ∂L/∂S ≈ ∂L/∂(W⊙M). In practice this is implemented by computing the mask in the forward pass without tracking it in the autograd graph, then multiplying the weight by the detached mask. The score gradient then equals the gradient through the weight times the mask indicator."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.autograd import Function\n\nclass TopKSTE(Function):\n    \"\"\"Straight-through estimator for top-k masking.\"\"\"\n\n    @staticmethod\n    def forward(ctx, scores: torch.Tensor, sparsity: float):\n        n_keep = max(1, int(scores.numel() * (1 - sparsity)))\n        threshold = scores.abs().flatten().topk(n_keep).values.min()\n        mask = (scores.abs() \u003e= threshold).float()\n        ctx.save_for_backward(mask)\n        return mask\n\n    @staticmethod\n    def backward(ctx, grad_output):\n        # STE: pass gradient straight through the masking operation\n        mask, = ctx.saved_tensors\n        return grad_output * mask, None  # None for sparsity (not a tensor)\n\nclass MovementPruningLinearSTE(nn.Module):\n    def __init__(self, in_features, out_features, sparsity=0.8):\n        super().__init__()\n        self.weight = nn.Parameter(torch.randn(out_features, in_features) * 0.02)\n        self.bias = nn.Parameter(torch.zeros(out_features))\n        self.scores = nn.Parameter(torch.zeros(out_features, in_features))\n        self.sparsity = sparsity\n\n    def forward(self, x):\n        mask = TopKSTE.apply(self.scores, self.sparsity)\n        return nn.functional.linear(x * 1.0, self.weight * mask, self.bias)\n\n# Test gradient flows to scores\nlayer = MovementPruningLinearSTE(32, 16, sparsity=0.7)\nx = torch.randn(4, 32)\nloss = layer(x).sum()\nloss.backward()\nprint(f\u0027scores.grad is None: {layer.scores.grad is None}\u0027)\nprint(f\u0027scores.grad norm: {layer.scores.grad.norm().item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Movement vs Magnitude — BERT-QA Accuracy"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib\nmatplotlib.use(\u0027Agg\u0027)\nimport matplotlib.pyplot as plt\n\n# Reproduced from Sanh et al. 2020 (SQuAD v1.1 F1 at varying sparsity)\nsparsity_levels = [0.0, 0.5, 0.7, 0.8, 0.85, 0.90, 0.95]\n\n# Approximate F1 scores from paper (BERT-base fine-tuned on SQuAD)\nmagnitude_f1 = [88.5, 87.9, 86.1, 82.4, 78.3, 68.2, 45.1]\nmovement_f1  = [88.5, 88.2, 87.6, 86.8, 85.1, 82.4, 74.3]\n\nprint(f\u0027{\"Sparsity\":\u003e10}  {\"Magnitude F1\":\u003e14}  {\"Movement F1\":\u003e12}  {\"Delta\":\u003e8}\u0027)\nprint(\u0027-\u0027 * 52)\nfor s, m, mv in zip(sparsity_levels, magnitude_f1, movement_f1):\n    print(f\u0027{s:\u003e10.0%}  {m:\u003e14.1f}  {mv:\u003e12.1f}  {mv-m:\u003e+8.1f}\u0027)\n\n# Find crossover: at what sparsity does movement pruning gain \u003e2 F1 points?\ncrossover = [(s, mv-m) for s, m, mv in zip(sparsity_levels, magnitude_f1, movement_f1)\n             if mv - m \u003e 2]\nif crossover:\n    print(f\u0027\\nMovement pruning gains \u003e2 F1 at sparsity \u003e= {crossover[0][0]:.0%}\u0027)\n    print(f\u0027Max gain: +{max(d for _,d in crossover):.1f} F1 at highest sparsity\u0027)"},{"type":"heading","level":2,"content":"Soft Movement Pruning"},{"type":"text","content":"Hard movement pruning uses a discrete top-k mask. Soft movement pruning relaxes this: instead of enforcing exact sparsity via top-k, it adds an L1 regularization term on the scores: L_total = L_task + λ · ‖S‖₁. This drives most scores toward zero while allowing the model to choose which ones remain nonzero. There is no hard sparsity constraint; the regularization strength λ controls the trade-off. At convergence, remaining nonzero scores define the surviving weights."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\n\nclass SoftMovementPruningLinear(nn.Module):\n    def __init__(self, in_features, out_features):\n        super().__init__()\n        self.weight = nn.Parameter(torch.randn(out_features, in_features) * 0.02)\n        self.bias = nn.Parameter(torch.zeros(out_features))\n        self.scores = nn.Parameter(torch.zeros(out_features, in_features))\n\n    def forward(self, x):\n        # Use sigmoid to get soft [0,1] mask (no discrete top-k)\n        soft_mask = torch.sigmoid(self.scores * 10)  # sharp sigmoid\n        return nn.functional.linear(x, self.weight * soft_mask, self.bias)\n\n    def l1_score_loss(self):\n        return self.scores.abs().mean()\n\ndef train_with_soft_movement(model, loader, criterion, epochs=3, lam=1e-4):\n    optimizer = optim.AdamW(model.parameters(), lr=2e-4)\n    for epoch in range(epochs):\n        total_task, total_reg = 0.0, 0.0\n        for X, y in loader:\n            optimizer.zero_grad()\n            task_loss = criterion(model(X), y)\n            # L1 regularization on all score tensors\n            reg_loss = sum(m.l1_score_loss() for m in model.modules()\n                          if isinstance(m, SoftMovementPruningLinear))\n            loss = task_loss + lam * reg_loss\n            loss.backward()\n            optimizer.step()\n            total_task += task_loss.item()\n            total_reg += reg_loss.item()\n        print(f\u0027Epoch {epoch+1}: task={total_task/len(loader):.4f}  reg={total_reg/len(loader):.4f}\u0027)\n\nprint(\u0027Soft movement pruning: scores driven to zero via L1, no discrete mask needed.\u0027)"},{"type":"callout","variant":"info","title":"When to Choose Movement Pruning","content":"Movement pruning is specifically designed for fine-tuning pretrained models like BERT. If you are training from scratch, magnitude pruning or Taylor pruning is equally effective. Movement pruning\u0027s advantage emerges because pre-trained weights that were large in the original model may become irrelevant after task-specific fine-tuning — magnitude pruning would keep them, while movement pruning correctly identifies and removes them."},{"type":"heading","level":2,"content":"Winning Tickets at Task-Specific Level"},{"type":"text","content":"The lottery ticket hypothesis states that large networks contain sparse subnetworks (winning tickets) that, when trained from initialization, match the full network\u0027s accuracy. Movement pruning finds winning tickets at the fine-tuning level: the sparse mask found by movement pruning on a fine-tuned BERT is task-specific and does not generalize across tasks. This is evidence that the lottery ticket structure is downstream of the task, not just of the pre-training."},{"type":"list","ordered":false,"items":["Scores S initialized to 0 at the start of fine-tuning — movement from zero signals importance.","Top-k masking: exactly (1-k)% of weights are pruned; k is the target density.","STE propagates gradients through discrete mask: score gradient ≈ weight gradient × mask.","Soft variant: L1 penalty on scores avoids discrete top-k, smoother optimization landscape.","At 80–90% sparsity, movement pruning retains 4–14 F1 points more than magnitude pruning on SQuAD.","Task-specific tickets: the winning subnetwork is different for QA vs NLI vs sentiment tasks."]},{"type":"heading","level":2,"content":"Pruning Criteria Comparison"},{"type":"table","headers":["Method","When Scores Computed","Criteria","BERT SQuAD F1 @ 90%","Supports Structure"],"rows":[["Magnitude pruning","Post-training, no gradient","|W_i| — static weight size","~68 F1","Yes (filter L1)"],["Movement pruning","During fine-tuning, gradient","Score S_i trained by ∂L/∂S","~82 F1","No — unstructured"],["Soft movement","During fine-tuning, gradient","L1(S) regularization, sigmoid mask","~81 F1","No — unstructured"],["SNIP","Before training (single pass)","|∂L/∂W_i · W_i| at init","~72 F1","Yes with extension"],["GraSP","Before training (Hessian approx)","-Hᵀg · W at init (gradient flow)","~74 F1","Limited"]]},{"type":"heading","level":2,"content":"Practical Recommendations for BERT Pruning"},{"type":"text","content":"For fine-tuned BERT models, apply movement pruning rather than magnitude pruning whenever sparsity exceeds 60%. Use a linear sparsity schedule: start at 0% and ramp to the target over the first 80% of fine-tuning steps, then hold the mask fixed for the remaining 20%. This warm-up avoids removing weights before the model has adapted to the task. Learning rate for scores should be 10–100× lower than the learning rate for weights; otherwise scores converge too fast and freeze before the model finds the best sparse subnetwork."},{"type":"list","ordered":false,"items":["Start fine-tuning with magnitude pruning warm-up (0→20% sparsity) before switching to movement scores.","Score learning rate: 1e-2 to 1e-1 (much higher than weight LR 2e-5) works well empirically.","Monitor gradient norms of scores — if they vanish, the temperature or LR needs adjustment.","After reaching target sparsity, freeze the mask and fine-tune weights only for 10% more steps.","For extreme sparsity (\u003e95%), combine movement pruning with distillation from the dense teacher."]},{"type":"divider"}]"
---
# Movement Pruning — Learning Which Weights to Prune

Magnitude pruning removes the smallest weights by absolute value. This works well for models trained from scratch but is poorly suited to fine-tuned models: during task-specific fine-tuning, the weights that matter most for the task may be small in magnitude but moving strongly away from zero, while large pre-trained weights that are irrelevant to the task remain large but become unimportant. Movement pruning addresses this by pruning weights that move toward zero during fine-tuning, learning which weights to keep jointly with the task objective.

## The Movement Pruning Objective

Movement pruning (Sanh et al. 2020) introduces a real-valued score S_i for each weight W_i, initialized to zero. During training, a binary mask is derived by keeping the top-k weights by score: M = top-k(|S|). The forward pass uses W ⊙ M (masked weights). The gradient of the task loss ∂L/∂S flows through the straight-through estimator, allowing the scores to be trained even though the masking operation is discrete. A positive score gradient means the weight is becoming more important; a negative gradient drives the score toward zero, eventually pruning the weight.

## Score Computation and Mask Generation

```python
import torch
import torch.nn as nn

class MovementPruningLinear(nn.Module):
    """Linear layer with learnable movement pruning scores."""

    def __init__(self, in_features: int, out_features: int, sparsity: float = 0.8):
        super().__init__()
        self.weight = nn.Parameter(torch.randn(out_features, in_features) * 0.02)
        self.bias = nn.Parameter(torch.zeros(out_features))
        self.scores = nn.Parameter(torch.zeros_like(self.weight))  # S_i = 0 initially
        self.sparsity = sparsity

    def _get_mask(self) -> torch.Tensor:
        n_keep = max(1, int(self.weight.numel() * (1 - self.sparsity)))
        # Top-k by absolute score value
        threshold = self.scores.abs().flatten().topk(n_keep).values.min()
        return (self.scores.abs() >= threshold).float()

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        mask = self._get_mask()  # binary, non-differentiable
        masked_weight = self.weight * mask  # scores gradient via STE (see next block)
        return nn.functional.linear(x, masked_weight, self.bias)

# Verify score shapes
layer = MovementPruningLinear(128, 64, sparsity=0.8)
x = torch.randn(8, 128)
out = layer(x)
print(f'Output shape: {out.shape}')
print(f'Score shape: {layer.scores.shape}')
print(f'Active weights: {layer._get_mask().sum().item():.0f}/{layer.weight.numel()}')
```

## Straight-Through Estimator for Discrete Masks

The top-k masking operation has zero gradient almost everywhere. The straight-through estimator (STE) bypasses this by passing the upstream gradient through the masking operation unchanged during the backward pass: ∂L/∂S ≈ ∂L/∂(W⊙M). In practice this is implemented by computing the mask in the forward pass without tracking it in the autograd graph, then multiplying the weight by the detached mask. The score gradient then equals the gradient through the weight times the mask indicator.

```python
import torch
import torch.nn as nn
from torch.autograd import Function

class TopKSTE(Function):
    """Straight-through estimator for top-k masking."""

    @staticmethod
    def forward(ctx, scores: torch.Tensor, sparsity: float):
        n_keep = max(1, int(scores.numel() * (1 - sparsity)))
        threshold = scores.abs().flatten().topk(n_keep).values.min()
        mask = (scores.abs() >= threshold).float()
        ctx.save_for_backward(mask)
        return mask

    @staticmethod
    def backward(ctx, grad_output):
        # STE: pass gradient straight through the masking operation
        mask, = ctx.saved_tensors
        return grad_output * mask, None  # None for sparsity (not a tensor)

class MovementPruningLinearSTE(nn.Module):
    def __init__(self, in_features, out_features, sparsity=0.8):
        super().__init__()
        self.weight = nn.Parameter(torch.randn(out_features, in_features) * 0.02)
        self.bias = nn.Parameter(torch.zeros(out_features))
        self.scores = nn.Parameter(torch.zeros(out_features, in_features))
        self.sparsity = sparsity

    def forward(self, x):
        mask = TopKSTE.apply(self.scores, self.sparsity)
        return nn.functional.linear(x * 1.0, self.weight * mask, self.bias)

# Test gradient flows to scores
layer = MovementPruningLinearSTE(32, 16, sparsity=0.7)
x = torch.randn(4, 32)
loss = layer(x).sum()
loss.backward()
print(f'scores.grad is None: {layer.scores.grad is None}')
print(f'scores.grad norm: {layer.scores.grad.norm().item():.4f}')
```

## Movement vs Magnitude — BERT-QA Accuracy

```python
import numpy as np
import matplotlib
matplotlib.use('Agg')
import matplotlib.pyplot as plt

# Reproduced from Sanh et al. 2020 (SQuAD v1.1 F1 at varying sparsity)
sparsity_levels = [0.0, 0.5, 0.7, 0.8, 0.85, 0.90, 0.95]

# Approximate F1 scores from paper (BERT-base fine-tuned on SQuAD)
magnitude_f1 = [88.5, 87.9, 86.1, 82.4, 78.3, 68.2, 45.1]
movement_f1  = [88.5, 88.2, 87.6, 86.8, 85.1, 82.4, 74.3]

print(f'{"Sparsity":>10}  {"Magnitude F1":>14}  {"Movement F1":>12}  {"Delta":>8}')
print('-' * 52)
for s, m, mv in zip(sparsity_levels, magnitude_f1, movement_f1):
    print(f'{s:>10.0%}  {m:>14.1f}  {mv:>12.1f}  {mv-m:>+8.1f}')

# Find crossover: at what sparsity does movement pruning gain >2 F1 points?
crossover = [(s, mv-m) for s, m, mv in zip(sparsity_levels, magnitude_f1, movement_f1)
             if mv - m > 2]
if crossover:
    print(f'\nMovement pruning gains >2 F1 at sparsity >= {crossover[0][0]:.0%}')
    print(f'Max gain: +{max(d for _,d in crossover):.1f} F1 at highest sparsity')
```

## Soft Movement Pruning

Hard movement pruning uses a discrete top-k mask. Soft movement pruning relaxes this: instead of enforcing exact sparsity via top-k, it adds an L1 regularization term on the scores: L_total = L_task + λ · ‖S‖₁. This drives most scores toward zero while allowing the model to choose which ones remain nonzero. There is no hard sparsity constraint; the regularization strength λ controls the trade-off. At convergence, remaining nonzero scores define the surviving weights.

```python
import torch
import torch.nn as nn
import torch.optim as optim

class SoftMovementPruningLinear(nn.Module):
    def __init__(self, in_features, out_features):
        super().__init__()
        self.weight = nn.Parameter(torch.randn(out_features, in_features) * 0.02)
        self.bias = nn.Parameter(torch.zeros(out_features))
        self.scores = nn.Parameter(torch.zeros(out_features, in_features))

    def forward(self, x):
        # Use sigmoid to get soft [0,1] mask (no discrete top-k)
        soft_mask = torch.sigmoid(self.scores * 10)  # sharp sigmoid
        return nn.functional.linear(x, self.weight * soft_mask, self.bias)

    def l1_score_loss(self):
        return self.scores.abs().mean()

def train_with_soft_movement(model, loader, criterion, epochs=3, lam=1e-4):
    optimizer = optim.AdamW(model.parameters(), lr=2e-4)
    for epoch in range(epochs):
        total_task, total_reg = 0.0, 0.0
        for X, y in loader:
            optimizer.zero_grad()
            task_loss = criterion(model(X), y)
            # L1 regularization on all score tensors
            reg_loss = sum(m.l1_score_loss() for m in model.modules()
                          if isinstance(m, SoftMovementPruningLinear))
            loss = task_loss + lam * reg_loss
            loss.backward()
            optimizer.step()
            total_task += task_loss.item()
            total_reg += reg_loss.item()
        print(f'Epoch {epoch+1}: task={total_task/len(loader):.4f}  reg={total_reg/len(loader):.4f}')

print('Soft movement pruning: scores driven to zero via L1, no discrete mask needed.')
```

> **When to Choose Movement Pruning**: Movement pruning is specifically designed for fine-tuning pretrained models like BERT. If you are training from scratch, magnitude pruning or Taylor pruning is equally effective. Movement pruning's advantage emerges because pre-trained weights that were large in the original model may become irrelevant after task-specific fine-tuning — magnitude pruning would keep them, while movement pruning correctly identifies and removes them.

## Winning Tickets at Task-Specific Level

The lottery ticket hypothesis states that large networks contain sparse subnetworks (winning tickets) that, when trained from initialization, match the full network's accuracy. Movement pruning finds winning tickets at the fine-tuning level: the sparse mask found by movement pruning on a fine-tuned BERT is task-specific and does not generalize across tasks. This is evidence that the lottery ticket structure is downstream of the task, not just of the pre-training.

- Scores S initialized to 0 at the start of fine-tuning — movement from zero signals importance.
- Top-k masking: exactly (1-k)% of weights are pruned; k is the target density.
- STE propagates gradients through discrete mask: score gradient ≈ weight gradient × mask.
- Soft variant: L1 penalty on scores avoids discrete top-k, smoother optimization landscape.
- At 80–90% sparsity, movement pruning retains 4–14 F1 points more than magnitude pruning on SQuAD.
- Task-specific tickets: the winning subnetwork is different for QA vs NLI vs sentiment tasks.

## Pruning Criteria Comparison

| Method | When Scores Computed | Criteria | BERT SQuAD F1 @ 90% | Supports Structure |
| --- | --- | --- | --- | --- |
| Magnitude pruning | Post-training, no gradient | |W_i| — static weight size | ~68 F1 | Yes (filter L1) |
| Movement pruning | During fine-tuning, gradient | Score S_i trained by ∂L/∂S | ~82 F1 | No — unstructured |
| Soft movement | During fine-tuning, gradient | L1(S) regularization, sigmoid mask | ~81 F1 | No — unstructured |
| SNIP | Before training (single pass) | |∂L/∂W_i · W_i| at init | ~72 F1 | Yes with extension |
| GraSP | Before training (Hessian approx) | -Hᵀg · W at init (gradient flow) | ~74 F1 | Limited |

## Practical Recommendations for BERT Pruning

For fine-tuned BERT models, apply movement pruning rather than magnitude pruning whenever sparsity exceeds 60%. Use a linear sparsity schedule: start at 0% and ramp to the target over the first 80% of fine-tuning steps, then hold the mask fixed for the remaining 20%. This warm-up avoids removing weights before the model has adapted to the task. Learning rate for scores should be 10–100× lower than the learning rate for weights; otherwise scores converge too fast and freeze before the model finds the best sparse subnetwork.

- Start fine-tuning with magnitude pruning warm-up (0→20% sparsity) before switching to movement scores.
- Score learning rate: 1e-2 to 1e-1 (much higher than weight LR 2e-5) works well empirically.
- Monitor gradient norms of scores — if they vanish, the temperature or LR needs adjustment.
- After reaching target sparsity, freeze the mask and fine-tune weights only for 10% more steps.
- For extreme sparsity (>95%), combine movement pruning with distillation from the dense teacher.

---

