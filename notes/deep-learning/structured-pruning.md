---
title: "Structured Pruning — Filter, Channel, and Layer Removal"
slug: "structured-pruning"
description: "Remove entire filters, channels, or layers to produce dense, hardware-acceleratable models. Covers L1-norm and Taylor expansion criteria, attention head pruning, layer pruning, iterative schedules, and reconstruction-based methods like HRank."
tags: ["deep-learning", "model-compression", "pruning", "quantization"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Unstructured pruning sets individual weights to zero, producing sparse weight matrices. Without specialized sparse-matrix hardware, these zero weights still consume memory and participate in matrix multiplications — yielding no wall-clock speedup on a standard GPU. Structured pruning solves this by removing entire filters, channels, or layers. The resulting model is dense and smaller; standard BLAS routines and GPU tensor cores immediately accelerate it without any special handling."},{"type":"heading","level":2,"content":"Why Structure Matters for Speedup"},{"type":"text","content":"A convolutional layer with 256 output filters and 50% unstructured sparsity still performs 256 output-channel dot products — half the FLOPs are wasted on multiplying by zero, but the loop count is unchanged. Remove 128 entire filters and the layer now performs 128 dot products with no zero arithmetic. This gives a 2× FLOP reduction that translates directly to throughput on any hardware. Structured pruning therefore reduces FLOPS, not just parameter count."},{"type":"heading","level":2,"content":"Filter Pruning with L1-Norm Criterion"},{"type":"text","content":"For a conv layer with weight tensor W ∈ ℝ^{C_out × C_in × k × k}, each output filter i has importance score s_i = ‖W_i‖₁ — the sum of absolute values across all elements of that filter. Filters with low L1-norm contribute little to the output feature map. After ranking all filters by s_i, the bottom p% are removed. The subsequent layer\u0027s input channels must be pruned correspondingly: removing filter i from layer l removes input channel i from layer l+1."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef prune_conv_layer(conv: nn.Conv2d, prune_ratio: float):\n    \"\"\"Prune bottom prune_ratio filters by L1 norm. Returns new Conv2d.\"\"\"\n    with torch.no_grad():\n        W = conv.weight.data  # (C_out, C_in, kH, kW)\n        scores = W.abs().sum(dim=(1, 2, 3))  # L1 norm per filter\n        n_keep = max(1, int(W.shape[0] * (1 - prune_ratio)))\n        keep_idx = scores.topk(n_keep).indices.sort().values\n\n        new_conv = nn.Conv2d(\n            in_channels=W.shape[1],\n            out_channels=n_keep,\n            kernel_size=conv.kernel_size,\n            stride=conv.stride,\n            padding=conv.padding,\n            bias=conv.bias is not None,\n        )\n        new_conv.weight.data = W[keep_idx]\n        if conv.bias is not None:\n            new_conv.bias.data = conv.bias.data[keep_idx]\n    return new_conv, keep_idx\n\ndef prune_bn_layer(bn: nn.BatchNorm2d, keep_idx: torch.Tensor):\n    new_bn = nn.BatchNorm2d(len(keep_idx))\n    new_bn.weight.data = bn.weight.data[keep_idx]\n    new_bn.bias.data = bn.bias.data[keep_idx]\n    new_bn.running_mean = bn.running_mean[keep_idx]\n    new_bn.running_var = bn.running_var[keep_idx]\n    return new_bn\n\n# Demo\nconv = nn.Conv2d(64, 128, 3, padding=1)\nconv_pruned, kept = prune_conv_layer(conv, prune_ratio=0.4)\nprint(f\u0027Original: {conv.weight.shape}  -\u003e Pruned: {conv_pruned.weight.shape}\u0027)\nprint(f\u0027Kept filter indices (first 5): {kept[:5].tolist()}\u0027)"},{"type":"heading","level":2,"content":"Taylor Expansion Importance Score"},{"type":"text","content":"The L1-norm criterion ignores gradient information. A filter with large weights but zero gradient contributes little to the loss. The Taylor expansion criterion approximates the change in loss when filter i is removed: ΔL ≈ Σ_j |g_j · w_j| where g_j = ∂L/∂w_j. This first-order approximation is computed in a single forward+backward pass over a calibration set and captures how sensitive the loss is to each filter\u0027s weights."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom collections import defaultdict\n\nclass TaylorPruner:\n    def __init__(self, model: nn.Module):\n        self.model = model\n        self.scores = defaultdict(float)\n        self._hooks = []\n        self._register_hooks()\n\n    def _register_hooks(self):\n        for name, module in self.model.named_modules():\n            if isinstance(module, nn.Conv2d):\n                h = module.weight.register_hook(\n                    lambda grad, n=name, m=module: self._accumulate(n, grad, m)\n                )\n                self._hooks.append(h)\n\n    def _accumulate(self, name, grad, module):\n        with torch.no_grad():\n            # Taylor score per output filter: sum |grad * weight| over C_in, kH, kW\n            score = (grad * module.weight.data).abs().sum(dim=(1, 2, 3))\n            if name not in self.scores:\n                self.scores[name] = score\n            else:\n                self.scores[name] += score\n\n    def compute_rankings(self):\n        rankings = {}\n        for name, score in self.scores.items():\n            order = score.argsort()  # ascending: weakest filters first\n            rankings[name] = order\n        return rankings\n\n    def remove_hooks(self):\n        for h in self._hooks:\n            h.remove()\n\n# Usage\nmodel = nn.Sequential(nn.Conv2d(3, 32, 3), nn.ReLU(), nn.Conv2d(32, 64, 3))\npruner = TaylorPruner(model)\nx = torch.randn(4, 3, 32, 32)\nloss = model(x).mean()\nloss.backward()\nrankings = pruner.compute_rankings()\nfor name, rank in rankings.items():\n    print(f\u0027{name}: top-3 weakest filters = {rank[:3].tolist()}\u0027)"},{"type":"heading","level":2,"content":"Attention Head Pruning in Transformers"},{"type":"text","content":"Multi-head attention with H heads computes H parallel attention patterns and concatenates results. Not all heads are equally important — some heads attend to syntax, others to semantics, and some are nearly redundant. Head importance can be measured by the expected sensitivity ∂L/∂z for each head\u0027s contribution or by a simpler proxy: the L1 norm of the head\u0027s output projection slice. Removing a head sets its contribution to zero and removes the corresponding columns in W_O."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport math\n\ndef compute_head_importance(attn_output_weights, head_dim, n_heads):\n    \"\"\"\n    attn_output_weights: (batch, n_heads, seq, seq)\n    Returns importance score per head (variance of attention distribution).\n    \"\"\"\n    # Higher entropy = more uniform = less specialized = lower importance\n    eps = 1e-9\n    entropy = -(attn_output_weights * (attn_output_weights + eps).log()).sum(-1)  # (B,H,S)\n    # Low entropy heads are more selective -\u003e higher importance\n    importance = -entropy.mean(dim=(0, 2))  # (H,)\n    return importance\n\ndef prune_attention_heads(W_q, W_k, W_v, W_o, head_dim, heads_to_prune):\n    \"\"\"Zero out specified attention heads in W_q, W_k, W_v and matching W_o columns.\"\"\"\n    n_heads = W_q.shape[0] // head_dim\n    mask = torch.ones(n_heads, dtype=torch.bool)\n    mask[list(heads_to_prune)] = False\n    keep = mask.nonzero(as_tuple=True)[0]\n    print(f\u0027Keeping {keep.numel()}/{n_heads} heads\u0027)\n    # Slice projection weights\n    kept_rows = torch.cat([torch.arange(h*head_dim, (h+1)*head_dim) for h in keep.tolist()])\n    W_q_p = W_q[kept_rows]\n    W_k_p = W_k[kept_rows]\n    W_v_p = W_v[kept_rows]\n    W_o_p = W_o[:, kept_rows]  # output projection: cols correspond to heads\n    return W_q_p, W_k_p, W_v_p, W_o_p\n\nn_heads, head_dim, d_model = 8, 64, 512\nW_q = torch.randn(n_heads * head_dim, d_model)\nW_k = torch.randn(n_heads * head_dim, d_model)\nW_v = torch.randn(n_heads * head_dim, d_model)\nW_o = torch.randn(d_model, n_heads * head_dim)\nWq_p, Wk_p, Wv_p, Wo_p = prune_attention_heads(W_q, W_k, W_v, W_o, head_dim, heads_to_prune={2, 5})\nprint(f\u0027W_q: {W_q.shape} -\u003e {Wq_p.shape}\u0027)"},{"type":"heading","level":2,"content":"Layer Pruning and Depth Reduction"},{"type":"text","content":"For Transformer models, entire encoder or decoder layers can be removed — depth pruning. Layer importance is measured by comparing the model\u0027s output distribution before and after removing the layer, or by the cosine similarity between the layer\u0027s input and output (high similarity = nearly identity = low importance). Shallow-layer removal tends to hurt more than removing upper layers; empirically, middle layers in BERT encoders are most redundant."},{"type":"heading","level":2,"content":"Iterative Pruning with Fine-Tuning"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\n\ndef iterative_prune_and_finetune(\n    model, train_loader, criterion, device,\n    prune_steps=5, target_sparsity=0.5,\n    finetune_epochs=2, lr=1e-4\n):\n    \"\"\"\n    Iteratively prune prune_steps times, fine-tuning between steps.\n    Each step removes (target_sparsity / prune_steps) additional filters.\n    \"\"\"\n    sparsity_per_step = target_sparsity / prune_steps\n    optimizer = optim.Adam(model.parameters(), lr=lr)\n\n    for step in range(prune_steps):\n        current_sparsity = sparsity_per_step * (step + 1)\n        print(f\u0027\\nStep {step+1}/{prune_steps}: pruning to {current_sparsity:.0%} sparsity\u0027)\n\n        # Prune all Conv2d layers\n        for name, module in list(model.named_modules()):\n            if isinstance(module, nn.Conv2d) and module.weight.shape[0] \u003e 4:\n                scores = module.weight.data.abs().sum(dim=(1, 2, 3))\n                threshold = scores.quantile(sparsity_per_step)\n                mask = scores \u003e= threshold\n                with torch.no_grad():\n                    module.weight.data[~mask] = 0.0  # soft zero (keep shape)\n\n        # Fine-tune for a few epochs\n        model.train()\n        for epoch in range(finetune_epochs):\n            total_loss = 0\n            for X_batch, y_batch in train_loader:\n                X_batch, y_batch = X_batch.to(device), y_batch.to(device)\n                optimizer.zero_grad()\n                loss = criterion(model(X_batch), y_batch)\n                loss.backward()\n                optimizer.step()\n                total_loss += loss.item()\n            print(f\u0027  Epoch {epoch+1}: avg loss = {total_loss/len(train_loader):.4f}\u0027)\n\n    return model\n\nprint(\u0027Iterative pruning: prune -\u003e fine-tune -\u003e prune cycle defined.\u0027)"},{"type":"callout","variant":"tip","title":"Prune Then Fine-Tune, Not Fine-Tune Then Prune","content":"Pruning abruptly lowers accuracy. Always fine-tune after each pruning step to recover lost performance. For structured pruning at 50% filter removal, even 1–2 epochs of fine-tuning at a reduced learning rate (10× smaller than original) typically recovers within 1% of the baseline. Larger pruning ratios need more recovery steps."},{"type":"heading","level":2,"content":"Reconstruction-Based Methods (HRank, CHIP)"},{"type":"text","content":"Instead of weight-based scores, HRank measures the average rank of the feature maps produced by each filter over a batch of inputs. Low-rank feature maps carry less information and are pruned first. CHIP minimizes the L2 distance between the output feature maps of the pruned layer and the original layer, formulated as a least-squares channel selection problem. These reconstruction-based criteria are more accurate than L1-norm but require a calibration forward pass."},{"type":"list","ordered":false,"items":["HRank: prune filters producing low-rank feature maps (high rank = richer representation).","CHIP: select subset of channels minimising ‖F_original - F_pruned‖₂ via greedy or OMP.","Taylor criterion: one backward pass over calibration data, captures gradient × weight sensitivity.","Activation statistics: prune filters whose activations are near-zero across the calibration set.","Random pruning baseline: surprisingly competitive at low sparsity (\u003c30%), useful as sanity check."]},{"type":"heading","level":2,"content":"Pruning Strategy Comparison"},{"type":"table","headers":["Method","What Is Removed","GPU Speedup","Accuracy Impact","Hardware Dependency","Implementation Effort"],"rows":[["Unstructured","Individual weights","None (without SpMM HW)","Low at \u003c80% sparsity","Sparse tensor cores (A100)","Low — apply threshold mask"],["Filter pruning","Entire output filters","High — fewer conv outputs","Medium — update next layer","None — dense after pruning","Medium — reshape consecutive layers"],["Channel pruning","Input+output channels jointly","High — matches filter pruning","Medium","None","High — both layers must be consistent"],["Layer pruning","Entire Transformer blocks","Very high for large models","High if too aggressive","None","Low — skip layers in forward"],["Head pruning (Transformers)","Attention heads","Moderate (10–30%)","Low at \u003c50% heads removed","None","Medium — slice projection matrices"]]},{"type":"divider"}]"
---
# Structured Pruning — Filter, Channel, and Layer Removal

Unstructured pruning sets individual weights to zero, producing sparse weight matrices. Without specialized sparse-matrix hardware, these zero weights still consume memory and participate in matrix multiplications — yielding no wall-clock speedup on a standard GPU. Structured pruning solves this by removing entire filters, channels, or layers. The resulting model is dense and smaller; standard BLAS routines and GPU tensor cores immediately accelerate it without any special handling.

## Why Structure Matters for Speedup

A convolutional layer with 256 output filters and 50% unstructured sparsity still performs 256 output-channel dot products — half the FLOPs are wasted on multiplying by zero, but the loop count is unchanged. Remove 128 entire filters and the layer now performs 128 dot products with no zero arithmetic. This gives a 2× FLOP reduction that translates directly to throughput on any hardware. Structured pruning therefore reduces FLOPS, not just parameter count.

## Filter Pruning with L1-Norm Criterion

For a conv layer with weight tensor W ∈ ℝ^{C_out × C_in × k × k}, each output filter i has importance score s_i = ‖W_i‖₁ — the sum of absolute values across all elements of that filter. Filters with low L1-norm contribute little to the output feature map. After ranking all filters by s_i, the bottom p% are removed. The subsequent layer's input channels must be pruned correspondingly: removing filter i from layer l removes input channel i from layer l+1.

```python
import torch
import torch.nn as nn

def prune_conv_layer(conv: nn.Conv2d, prune_ratio: float):
    """Prune bottom prune_ratio filters by L1 norm. Returns new Conv2d."""
    with torch.no_grad():
        W = conv.weight.data  # (C_out, C_in, kH, kW)
        scores = W.abs().sum(dim=(1, 2, 3))  # L1 norm per filter
        n_keep = max(1, int(W.shape[0] * (1 - prune_ratio)))
        keep_idx = scores.topk(n_keep).indices.sort().values

        new_conv = nn.Conv2d(
            in_channels=W.shape[1],
            out_channels=n_keep,
            kernel_size=conv.kernel_size,
            stride=conv.stride,
            padding=conv.padding,
            bias=conv.bias is not None,
        )
        new_conv.weight.data = W[keep_idx]
        if conv.bias is not None:
            new_conv.bias.data = conv.bias.data[keep_idx]
    return new_conv, keep_idx

def prune_bn_layer(bn: nn.BatchNorm2d, keep_idx: torch.Tensor):
    new_bn = nn.BatchNorm2d(len(keep_idx))
    new_bn.weight.data = bn.weight.data[keep_idx]
    new_bn.bias.data = bn.bias.data[keep_idx]
    new_bn.running_mean = bn.running_mean[keep_idx]
    new_bn.running_var = bn.running_var[keep_idx]
    return new_bn

# Demo
conv = nn.Conv2d(64, 128, 3, padding=1)
conv_pruned, kept = prune_conv_layer(conv, prune_ratio=0.4)
print(f'Original: {conv.weight.shape}  -> Pruned: {conv_pruned.weight.shape}')
print(f'Kept filter indices (first 5): {kept[:5].tolist()}')
```

## Taylor Expansion Importance Score

The L1-norm criterion ignores gradient information. A filter with large weights but zero gradient contributes little to the loss. The Taylor expansion criterion approximates the change in loss when filter i is removed: ΔL ≈ Σ_j |g_j · w_j| where g_j = ∂L/∂w_j. This first-order approximation is computed in a single forward+backward pass over a calibration set and captures how sensitive the loss is to each filter's weights.

```python
import torch
import torch.nn as nn
from collections import defaultdict

class TaylorPruner:
    def __init__(self, model: nn.Module):
        self.model = model
        self.scores = defaultdict(float)
        self._hooks = []
        self._register_hooks()

    def _register_hooks(self):
        for name, module in self.model.named_modules():
            if isinstance(module, nn.Conv2d):
                h = module.weight.register_hook(
                    lambda grad, n=name, m=module: self._accumulate(n, grad, m)
                )
                self._hooks.append(h)

    def _accumulate(self, name, grad, module):
        with torch.no_grad():
            # Taylor score per output filter: sum |grad * weight| over C_in, kH, kW
            score = (grad * module.weight.data).abs().sum(dim=(1, 2, 3))
            if name not in self.scores:
                self.scores[name] = score
            else:
                self.scores[name] += score

    def compute_rankings(self):
        rankings = {}
        for name, score in self.scores.items():
            order = score.argsort()  # ascending: weakest filters first
            rankings[name] = order
        return rankings

    def remove_hooks(self):
        for h in self._hooks:
            h.remove()

# Usage
model = nn.Sequential(nn.Conv2d(3, 32, 3), nn.ReLU(), nn.Conv2d(32, 64, 3))
pruner = TaylorPruner(model)
x = torch.randn(4, 3, 32, 32)
loss = model(x).mean()
loss.backward()
rankings = pruner.compute_rankings()
for name, rank in rankings.items():
    print(f'{name}: top-3 weakest filters = {rank[:3].tolist()}')
```

## Attention Head Pruning in Transformers

Multi-head attention with H heads computes H parallel attention patterns and concatenates results. Not all heads are equally important — some heads attend to syntax, others to semantics, and some are nearly redundant. Head importance can be measured by the expected sensitivity ∂L/∂z for each head's contribution or by a simpler proxy: the L1 norm of the head's output projection slice. Removing a head sets its contribution to zero and removes the corresponding columns in W_O.

```python
import torch
import torch.nn as nn
import math

def compute_head_importance(attn_output_weights, head_dim, n_heads):
    """
    attn_output_weights: (batch, n_heads, seq, seq)
    Returns importance score per head (variance of attention distribution).
    """
    # Higher entropy = more uniform = less specialized = lower importance
    eps = 1e-9
    entropy = -(attn_output_weights * (attn_output_weights + eps).log()).sum(-1)  # (B,H,S)
    # Low entropy heads are more selective -> higher importance
    importance = -entropy.mean(dim=(0, 2))  # (H,)
    return importance

def prune_attention_heads(W_q, W_k, W_v, W_o, head_dim, heads_to_prune):
    """Zero out specified attention heads in W_q, W_k, W_v and matching W_o columns."""
    n_heads = W_q.shape[0] // head_dim
    mask = torch.ones(n_heads, dtype=torch.bool)
    mask[list(heads_to_prune)] = False
    keep = mask.nonzero(as_tuple=True)[0]
    print(f'Keeping {keep.numel()}/{n_heads} heads')
    # Slice projection weights
    kept_rows = torch.cat([torch.arange(h*head_dim, (h+1)*head_dim) for h in keep.tolist()])
    W_q_p = W_q[kept_rows]
    W_k_p = W_k[kept_rows]
    W_v_p = W_v[kept_rows]
    W_o_p = W_o[:, kept_rows]  # output projection: cols correspond to heads
    return W_q_p, W_k_p, W_v_p, W_o_p

n_heads, head_dim, d_model = 8, 64, 512
W_q = torch.randn(n_heads * head_dim, d_model)
W_k = torch.randn(n_heads * head_dim, d_model)
W_v = torch.randn(n_heads * head_dim, d_model)
W_o = torch.randn(d_model, n_heads * head_dim)
Wq_p, Wk_p, Wv_p, Wo_p = prune_attention_heads(W_q, W_k, W_v, W_o, head_dim, heads_to_prune={2, 5})
print(f'W_q: {W_q.shape} -> {Wq_p.shape}')
```

## Layer Pruning and Depth Reduction

For Transformer models, entire encoder or decoder layers can be removed — depth pruning. Layer importance is measured by comparing the model's output distribution before and after removing the layer, or by the cosine similarity between the layer's input and output (high similarity = nearly identity = low importance). Shallow-layer removal tends to hurt more than removing upper layers; empirically, middle layers in BERT encoders are most redundant.

## Iterative Pruning with Fine-Tuning

```python
import torch
import torch.nn as nn
import torch.optim as optim

def iterative_prune_and_finetune(
    model, train_loader, criterion, device,
    prune_steps=5, target_sparsity=0.5,
    finetune_epochs=2, lr=1e-4
):
    """
    Iteratively prune prune_steps times, fine-tuning between steps.
    Each step removes (target_sparsity / prune_steps) additional filters.
    """
    sparsity_per_step = target_sparsity / prune_steps
    optimizer = optim.Adam(model.parameters(), lr=lr)

    for step in range(prune_steps):
        current_sparsity = sparsity_per_step * (step + 1)
        print(f'\nStep {step+1}/{prune_steps}: pruning to {current_sparsity:.0%} sparsity')

        # Prune all Conv2d layers
        for name, module in list(model.named_modules()):
            if isinstance(module, nn.Conv2d) and module.weight.shape[0] > 4:
                scores = module.weight.data.abs().sum(dim=(1, 2, 3))
                threshold = scores.quantile(sparsity_per_step)
                mask = scores >= threshold
                with torch.no_grad():
                    module.weight.data[~mask] = 0.0  # soft zero (keep shape)

        # Fine-tune for a few epochs
        model.train()
        for epoch in range(finetune_epochs):
            total_loss = 0
            for X_batch, y_batch in train_loader:
                X_batch, y_batch = X_batch.to(device), y_batch.to(device)
                optimizer.zero_grad()
                loss = criterion(model(X_batch), y_batch)
                loss.backward()
                optimizer.step()
                total_loss += loss.item()
            print(f'  Epoch {epoch+1}: avg loss = {total_loss/len(train_loader):.4f}')

    return model

print('Iterative pruning: prune -> fine-tune -> prune cycle defined.')
```

> **Prune Then Fine-Tune, Not Fine-Tune Then Prune**: Pruning abruptly lowers accuracy. Always fine-tune after each pruning step to recover lost performance. For structured pruning at 50% filter removal, even 1–2 epochs of fine-tuning at a reduced learning rate (10× smaller than original) typically recovers within 1% of the baseline. Larger pruning ratios need more recovery steps.

## Reconstruction-Based Methods (HRank, CHIP)

Instead of weight-based scores, HRank measures the average rank of the feature maps produced by each filter over a batch of inputs. Low-rank feature maps carry less information and are pruned first. CHIP minimizes the L2 distance between the output feature maps of the pruned layer and the original layer, formulated as a least-squares channel selection problem. These reconstruction-based criteria are more accurate than L1-norm but require a calibration forward pass.

- HRank: prune filters producing low-rank feature maps (high rank = richer representation).
- CHIP: select subset of channels minimising ‖F_original - F_pruned‖₂ via greedy or OMP.
- Taylor criterion: one backward pass over calibration data, captures gradient × weight sensitivity.
- Activation statistics: prune filters whose activations are near-zero across the calibration set.
- Random pruning baseline: surprisingly competitive at low sparsity (<30%), useful as sanity check.

## Pruning Strategy Comparison

| Method | What Is Removed | GPU Speedup | Accuracy Impact | Hardware Dependency | Implementation Effort |
| --- | --- | --- | --- | --- | --- |
| Unstructured | Individual weights | None (without SpMM HW) | Low at <80% sparsity | Sparse tensor cores (A100) | Low — apply threshold mask |
| Filter pruning | Entire output filters | High — fewer conv outputs | Medium — update next layer | None — dense after pruning | Medium — reshape consecutive layers |
| Channel pruning | Input+output channels jointly | High — matches filter pruning | Medium | None | High — both layers must be consistent |
| Layer pruning | Entire Transformer blocks | Very high for large models | High if too aggressive | None | Low — skip layers in forward |
| Head pruning (Transformers) | Attention heads | Moderate (10–30%) | Low at <50% heads removed | None | Medium — slice projection matrices |

---

