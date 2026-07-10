---
title: "Pre-Norm vs Post-Norm Transformers — Stability and Performance"
slug: "pre-norm-vs-post-norm"
description: "Comparing the original post-norm Transformer (Vaswani 2017) with the modern pre-norm layout used in GPT-2 and LLaMA: training stability, gradient flow, and the Sandwich normalisation variant."
tags: ["deep-learning", "transformers"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The placement of Layer Normalisation inside a Transformer block has a surprisingly large effect on training stability and the ability to scale to deep models. The original Vaswani et al. (2017) architecture applies LayerNorm *after* each residual connection — post-norm. Nearly all modern large language models (GPT-2, LLaMA, Mistral) instead apply LayerNorm *before* the sub-layer — pre-norm. The difference is one line of code, but its training implications are significant."},{"type":"heading","level":2,"content":"Post-Norm — The Original Transformer Design"},{"type":"text","content":"In the post-norm formulation (Vaswani 2017), the residual and the sub-layer output are summed first, then normalised: x = LayerNorm(x + Sublayer(x)). LayerNorm sees the combined residual stream and stabilises it. The problem is that at initialisation, the Jacobian of LayerNorm with respect to its input can have extreme eigenvalues, leading to unstable gradients in very deep networks. Training post-norm models typically requires a careful learning rate warmup schedule to prevent divergence in the first few thousand steps."},{"type":"list","ordered":false,"items":["Post-norm attention: x = LayerNorm(x + MultiHeadAttn(x))","Post-norm FFN:      x = LayerNorm(x + FFN(x))","Requires warmup: LR must ramp from near-zero to peak over ~4000 steps","Final quality: empirically slightly better at convergence for shallow models","Deep models (24+ layers): training instability is common without careful tuning"]},{"type":"callout","variant":"info","title":"Pre-LN Transformers Paper (Liu et al. 2020)","content":"The paper \u0027On the Variance of the Adaptive Learning Rate and Beyond\u0027 and the \u0027Pre-LN Transformer\u0027 analysis (Liu et al.) showed that post-norm models have extremely large gradient variance at initialisation, which is why warmup is essential. Pre-norm eliminates this instability because the residual path carries raw gradients whose magnitude is bounded independently of depth."},{"type":"heading","level":2,"content":"Pre-Norm — Modern LLMs and Training Stability"},{"type":"text","content":"In the pre-norm formulation, LayerNorm is applied to x before passing it to the sub-layer, and the result is added back to the un-normalised x: x = x + Sublayer(LayerNorm(x)). The residual bypass path carries raw gradients all the way back to the first layer, like a highway. This makes gradient magnitude approximately constant across depth at initialisation, enabling training at full learning rate without a warmup phase. GPT-2 adopted pre-norm and it has been the standard in LLMs ever since."},{"type":"heading","level":2,"content":"Gradient Flow Analysis"},{"type":"text","content":"The key difference in gradient behaviour comes from the residual path. In post-norm, gradients must flow through the LayerNorm Jacobian at each layer: the gradient magnitude can grow or shrink unpredictably with depth. In pre-norm, the residual connection bypasses LayerNorm entirely — a gradient flowing back through the residual path sees identity Jacobian, so its magnitude is preserved. Only the sub-layer branch (a fraction of the total gradient) passes through LayerNorm. This is why pre-norm models converge faster and require less careful hyperparameter tuning, even if their final perplexity sometimes lags post-norm by a small margin."},{"type":"heading","level":2,"content":"Code 1 — Pre-Norm Transformer Block"},{"type":"text","content":"The canonical pre-norm block used in GPT-2, LLaMA, and Mistral: LayerNorm is applied to the input before each sub-layer, and outputs are added to the un-normalised residual."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass PreNormBlock(nn.Module):\n    \"\"\"Pre-normalisation Transformer block (GPT-2 / LLaMA style).\n    x = x + Attn(LayerNorm(x))\n    x = x + FFN(LayerNorm(x))\n    \"\"\"\n    def __init__(self, d_model: int, n_heads: int, d_ff: int,\n                 dropout: float = 0.1):\n        super().__init__()\n        self.norm1 = nn.LayerNorm(d_model)\n        self.norm2 = nn.LayerNorm(d_model)\n        self.attn  = nn.MultiheadAttention(d_model, n_heads,\n                                            dropout=dropout, batch_first=True)\n        self.ff1   = nn.Linear(d_model, d_ff)\n        self.ff2   = nn.Linear(d_ff, d_model)\n        self.act   = nn.GELU()\n        self.drop  = nn.Dropout(dropout)\n\n    def forward(self, x: torch.Tensor,\n                attn_mask: torch.Tensor = None) -\u003e torch.Tensor:\n        # Self-attention sub-layer: norm BEFORE attention\n        normed  = self.norm1(x)\n        a, _    = self.attn(normed, normed, normed, attn_mask=attn_mask)\n        x       = x + self.drop(a)\n        # FFN sub-layer: norm BEFORE FFN\n        x = x + self.drop(self.ff2(self.act(self.ff1(self.norm2(x)))))\n        return x\n\n# Sanity check\nblock = PreNormBlock(d_model=256, n_heads=8, d_ff=1024)\ninp   = torch.randn(2, 10, 256)\nout   = block(inp)\nprint(\u0027Pre-norm output shape:\u0027, out.shape)      # (2, 10, 256)\nassert out.shape == inp.shape\nprint(\u0027Output norm (pre-norm — residual keeps scale):\u0027, out.norm(dim=-1).mean().item())"},{"type":"heading","level":2,"content":"Code 2 — Post-Norm Transformer Block"},{"type":"text","content":"The original Vaswani (2017) post-norm block: LayerNorm is applied after the residual addition, stabilising the hidden state at each sub-layer output."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass PostNormBlock(nn.Module):\n    \"\"\"Post-normalisation Transformer block (Vaswani 2017 original style).\n    x = LayerNorm(x + Attn(x))\n    x = LayerNorm(x + FFN(x))\n    \"\"\"\n    def __init__(self, d_model: int, n_heads: int, d_ff: int,\n                 dropout: float = 0.1):\n        super().__init__()\n        self.norm1 = nn.LayerNorm(d_model)\n        self.norm2 = nn.LayerNorm(d_model)\n        self.attn  = nn.MultiheadAttention(d_model, n_heads,\n                                            dropout=dropout, batch_first=True)\n        self.ff1   = nn.Linear(d_model, d_ff)\n        self.ff2   = nn.Linear(d_ff, d_model)\n        self.act   = nn.GELU()\n        self.drop  = nn.Dropout(dropout)\n\n    def forward(self, x: torch.Tensor,\n                attn_mask: torch.Tensor = None) -\u003e torch.Tensor:\n        # Self-attention sub-layer: norm AFTER residual\n        a, _ = self.attn(x, x, x, attn_mask=attn_mask)\n        x    = self.norm1(x + self.drop(a))\n        # FFN sub-layer: norm AFTER residual\n        x = self.norm2(x + self.drop(self.ff2(self.act(self.ff1(x)))))\n        return x\n\n# Sanity check\nblock = PostNormBlock(d_model=256, n_heads=8, d_ff=1024)\ninp   = torch.randn(2, 10, 256)\nout   = block(inp)\nprint(\u0027Post-norm output shape:\u0027, out.shape)     # (2, 10, 256)\n# Post-norm: LayerNorm stabilises output magnitude after each residual\nprint(\u0027Output norm (post-norm — LN normalises output):\u0027, out.norm(dim=-1).mean().item())\nprint(\u0027Input norm:\u0027, inp.norm(dim=-1).mean().item())"},{"type":"heading","level":2,"content":"Code 3 — Gradient Norm Comparison"},{"type":"text","content":"Empirically measuring gradient norms across 20 steps to illustrate that pre-norm keeps gradient magnitude more stable than post-norm for a 12-layer stack."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef build_stack(norm_type: str, n_layers: int = 12, d: int = 128):\n    \"\"\"Minimal feed-forward stack emulating pre vs post norm stacking.\"\"\"\n    layers = []\n    for _ in range(n_layers):\n        if norm_type == \u0027pre\u0027:\n            layers += [nn.LayerNorm(d), nn.Linear(d, d), nn.GELU(), nn.Linear(d, d)]\n        else:\n            layers += [nn.Linear(d, d), nn.GELU(), nn.Linear(d, d), nn.LayerNorm(d)]\n    return nn.Sequential(*layers)\n\ndef measure_grad_norm(model: nn.Module, x: torch.Tensor) -\u003e float:\n    x = x.detach().requires_grad_(False)\n    y = model(x).mean()\n    y.backward()\n    total_sq = sum(p.grad.norm().item()**2\n                   for p in model.parameters() if p.grad is not None)\n    model.zero_grad()\n    return total_sq ** 0.5\n\nd = 128\nx = torch.randn(4, d)\nresults = {}\nfor ntype in (\u0027pre\u0027, \u0027post\u0027):\n    torch.manual_seed(0)\n    model = build_stack(ntype, n_layers=12, d=d)\n    norms = []\n    for step in range(20):\n        xi = x + 0.01 * step * torch.randn_like(x)\n        norms.append(measure_grad_norm(model, xi))\n    results[ntype] = norms\n    mean_gn = sum(norms) / len(norms)\n    std_gn  = (sum((g - mean_gn)**2 for g in norms) / len(norms))**0.5\n    print(f\u0027{ntype}-norm: mean grad norm = {mean_gn:.4f}, std = {std_gn:.4f}\u0027)\nprint(\u0027Pre-norm has lower variance — more predictable gradient signal\u0027)"},{"type":"heading","level":2,"content":"Code 4 — Sandwich Normalisation"},{"type":"text","content":"Sandwich-LN (Ding et al. 2021, CogView) applies LayerNorm both before the sub-layer (pre) and after the residual (post), combining the stability of pre-norm with some of the quality benefits of post-norm."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass SandwichBlock(nn.Module):\n    \"\"\"Sandwich normalisation: LayerNorm before sublayer AND after residual.\n    x_attn = LayerNorm_post(x + Attn(LayerNorm_pre(x)))\n    x_ffn  = LayerNorm_post(x + FFN(LayerNorm_pre(x)))\n    Reference: Ding et al. (2021) CogView.\n    \"\"\"\n    def __init__(self, d_model: int, n_heads: int, d_ff: int):\n        super().__init__()\n        self.pre_attn  = nn.LayerNorm(d_model)\n        self.post_attn = nn.LayerNorm(d_model)\n        self.pre_ffn   = nn.LayerNorm(d_model)\n        self.post_ffn  = nn.LayerNorm(d_model)\n        self.attn = nn.MultiheadAttention(d_model, n_heads, batch_first=True)\n        self.ff1  = nn.Linear(d_model, d_ff)\n        self.ff2  = nn.Linear(d_ff, d_model)\n        self.act  = nn.GELU()\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        # Attention with pre- and post-normalisation\n        n = self.pre_attn(x)\n        a, _ = self.attn(n, n, n)\n        x = self.post_attn(x + a)\n        # FFN with pre- and post-normalisation\n        n = self.pre_ffn(x)\n        x = self.post_ffn(x + self.ff2(self.act(self.ff1(n))))\n        return x\n\ntorch.manual_seed(0)\nd_model, n_heads, d_ff = 256, 8, 1024\ninp   = torch.randn(2, 12, d_model)\nblock = SandwichBlock(d_model, n_heads, d_ff)\nout   = block(inp)\nprint(\u0027Sandwich block output:\u0027, out.shape)\nprint(\u0027Input  mean norm:\u0027, inp.norm(dim=-1).mean().item())\nprint(\u0027Output mean norm:\u0027, out.norm(dim=-1).mean().item())\nprint(\u0027Params:\u0027, sum(p.numel() for p in block.parameters()))"},{"type":"heading","level":2,"content":"Pre-Norm vs Post-Norm at a Glance"},{"type":"table","headers":["Property","Post-Norm (Vaswani 2017)","Pre-Norm (GPT-2, LLaMA)","Sandwich-Norm"],"rows":[["LN position","After residual addition","Before sub-layer input","Before and after sub-layer"],["LR warmup needed","Yes — required to prevent divergence","No — more forgiving LR schedule","Minimal — stable at init"],["Gradient flow","Through LN Jacobian (unpredictable)","Residual bypasses LN (stable)","Mixed: pre and post paths"],["Convergence quality","Slightly better at final perplexity","Slightly lower but reliable","On par or better"],["Stability at 24+ layers","Difficult — common divergence","Good — default choice","Best reported stability"],["Modern adoption","T5, older BERT variants","GPT-2/3/4, LLaMA, Mistral, Gemma","CogView, specialised models"]]},{"type":"text","content":"For new Transformer architectures, pre-norm is the safe default: it trains without warmup, scales to hundreds of layers, and requires less careful learning-rate tuning. Post-norm may recover a small quality margin when training is carefully managed with warmup, and is worth considering for smaller models where training stability is less of a concern. Sandwich-norm offers a middle ground but adds extra parameters and is used primarily in large image-generation models."}]"
---
# Pre-Norm vs Post-Norm Transformers — Stability and Performance

The placement of Layer Normalisation inside a Transformer block has a surprisingly large effect on training stability and the ability to scale to deep models. The original Vaswani et al. (2017) architecture applies LayerNorm *after* each residual connection — post-norm. Nearly all modern large language models (GPT-2, LLaMA, Mistral) instead apply LayerNorm *before* the sub-layer — pre-norm. The difference is one line of code, but its training implications are significant.

## Post-Norm — The Original Transformer Design

In the post-norm formulation (Vaswani 2017), the residual and the sub-layer output are summed first, then normalised: x = LayerNorm(x + Sublayer(x)). LayerNorm sees the combined residual stream and stabilises it. The problem is that at initialisation, the Jacobian of LayerNorm with respect to its input can have extreme eigenvalues, leading to unstable gradients in very deep networks. Training post-norm models typically requires a careful learning rate warmup schedule to prevent divergence in the first few thousand steps.

- Post-norm attention: x = LayerNorm(x + MultiHeadAttn(x))
- Post-norm FFN:      x = LayerNorm(x + FFN(x))
- Requires warmup: LR must ramp from near-zero to peak over ~4000 steps
- Final quality: empirically slightly better at convergence for shallow models
- Deep models (24+ layers): training instability is common without careful tuning

> **Pre-LN Transformers Paper (Liu et al. 2020)**: The paper 'On the Variance of the Adaptive Learning Rate and Beyond' and the 'Pre-LN Transformer' analysis (Liu et al.) showed that post-norm models have extremely large gradient variance at initialisation, which is why warmup is essential. Pre-norm eliminates this instability because the residual path carries raw gradients whose magnitude is bounded independently of depth.

## Pre-Norm — Modern LLMs and Training Stability

In the pre-norm formulation, LayerNorm is applied to x before passing it to the sub-layer, and the result is added back to the un-normalised x: x = x + Sublayer(LayerNorm(x)). The residual bypass path carries raw gradients all the way back to the first layer, like a highway. This makes gradient magnitude approximately constant across depth at initialisation, enabling training at full learning rate without a warmup phase. GPT-2 adopted pre-norm and it has been the standard in LLMs ever since.

## Gradient Flow Analysis

The key difference in gradient behaviour comes from the residual path. In post-norm, gradients must flow through the LayerNorm Jacobian at each layer: the gradient magnitude can grow or shrink unpredictably with depth. In pre-norm, the residual connection bypasses LayerNorm entirely — a gradient flowing back through the residual path sees identity Jacobian, so its magnitude is preserved. Only the sub-layer branch (a fraction of the total gradient) passes through LayerNorm. This is why pre-norm models converge faster and require less careful hyperparameter tuning, even if their final perplexity sometimes lags post-norm by a small margin.

## Code 1 — Pre-Norm Transformer Block

The canonical pre-norm block used in GPT-2, LLaMA, and Mistral: LayerNorm is applied to the input before each sub-layer, and outputs are added to the un-normalised residual.

```python
import torch
import torch.nn as nn

class PreNormBlock(nn.Module):
    """Pre-normalisation Transformer block (GPT-2 / LLaMA style).
    x = x + Attn(LayerNorm(x))
    x = x + FFN(LayerNorm(x))
    """
    def __init__(self, d_model: int, n_heads: int, d_ff: int,
                 dropout: float = 0.1):
        super().__init__()
        self.norm1 = nn.LayerNorm(d_model)
        self.norm2 = nn.LayerNorm(d_model)
        self.attn  = nn.MultiheadAttention(d_model, n_heads,
                                            dropout=dropout, batch_first=True)
        self.ff1   = nn.Linear(d_model, d_ff)
        self.ff2   = nn.Linear(d_ff, d_model)
        self.act   = nn.GELU()
        self.drop  = nn.Dropout(dropout)

    def forward(self, x: torch.Tensor,
                attn_mask: torch.Tensor = None) -> torch.Tensor:
        # Self-attention sub-layer: norm BEFORE attention
        normed  = self.norm1(x)
        a, _    = self.attn(normed, normed, normed, attn_mask=attn_mask)
        x       = x + self.drop(a)
        # FFN sub-layer: norm BEFORE FFN
        x = x + self.drop(self.ff2(self.act(self.ff1(self.norm2(x)))))
        return x

# Sanity check
block = PreNormBlock(d_model=256, n_heads=8, d_ff=1024)
inp   = torch.randn(2, 10, 256)
out   = block(inp)
print('Pre-norm output shape:', out.shape)      # (2, 10, 256)
assert out.shape == inp.shape
print('Output norm (pre-norm — residual keeps scale):', out.norm(dim=-1).mean().item())
```

## Code 2 — Post-Norm Transformer Block

The original Vaswani (2017) post-norm block: LayerNorm is applied after the residual addition, stabilising the hidden state at each sub-layer output.

```python
import torch
import torch.nn as nn

class PostNormBlock(nn.Module):
    """Post-normalisation Transformer block (Vaswani 2017 original style).
    x = LayerNorm(x + Attn(x))
    x = LayerNorm(x + FFN(x))
    """
    def __init__(self, d_model: int, n_heads: int, d_ff: int,
                 dropout: float = 0.1):
        super().__init__()
        self.norm1 = nn.LayerNorm(d_model)
        self.norm2 = nn.LayerNorm(d_model)
        self.attn  = nn.MultiheadAttention(d_model, n_heads,
                                            dropout=dropout, batch_first=True)
        self.ff1   = nn.Linear(d_model, d_ff)
        self.ff2   = nn.Linear(d_ff, d_model)
        self.act   = nn.GELU()
        self.drop  = nn.Dropout(dropout)

    def forward(self, x: torch.Tensor,
                attn_mask: torch.Tensor = None) -> torch.Tensor:
        # Self-attention sub-layer: norm AFTER residual
        a, _ = self.attn(x, x, x, attn_mask=attn_mask)
        x    = self.norm1(x + self.drop(a))
        # FFN sub-layer: norm AFTER residual
        x = self.norm2(x + self.drop(self.ff2(self.act(self.ff1(x)))))
        return x

# Sanity check
block = PostNormBlock(d_model=256, n_heads=8, d_ff=1024)
inp   = torch.randn(2, 10, 256)
out   = block(inp)
print('Post-norm output shape:', out.shape)     # (2, 10, 256)
# Post-norm: LayerNorm stabilises output magnitude after each residual
print('Output norm (post-norm — LN normalises output):', out.norm(dim=-1).mean().item())
print('Input norm:', inp.norm(dim=-1).mean().item())
```

## Code 3 — Gradient Norm Comparison

Empirically measuring gradient norms across 20 steps to illustrate that pre-norm keeps gradient magnitude more stable than post-norm for a 12-layer stack.

```python
import torch
import torch.nn as nn

def build_stack(norm_type: str, n_layers: int = 12, d: int = 128):
    """Minimal feed-forward stack emulating pre vs post norm stacking."""
    layers = []
    for _ in range(n_layers):
        if norm_type == 'pre':
            layers += [nn.LayerNorm(d), nn.Linear(d, d), nn.GELU(), nn.Linear(d, d)]
        else:
            layers += [nn.Linear(d, d), nn.GELU(), nn.Linear(d, d), nn.LayerNorm(d)]
    return nn.Sequential(*layers)

def measure_grad_norm(model: nn.Module, x: torch.Tensor) -> float:
    x = x.detach().requires_grad_(False)
    y = model(x).mean()
    y.backward()
    total_sq = sum(p.grad.norm().item()**2
                   for p in model.parameters() if p.grad is not None)
    model.zero_grad()
    return total_sq ** 0.5

d = 128
x = torch.randn(4, d)
results = {}
for ntype in ('pre', 'post'):
    torch.manual_seed(0)
    model = build_stack(ntype, n_layers=12, d=d)
    norms = []
    for step in range(20):
        xi = x + 0.01 * step * torch.randn_like(x)
        norms.append(measure_grad_norm(model, xi))
    results[ntype] = norms
    mean_gn = sum(norms) / len(norms)
    std_gn  = (sum((g - mean_gn)**2 for g in norms) / len(norms))**0.5
    print(f'{ntype}-norm: mean grad norm = {mean_gn:.4f}, std = {std_gn:.4f}')
print('Pre-norm has lower variance — more predictable gradient signal')
```

## Code 4 — Sandwich Normalisation

Sandwich-LN (Ding et al. 2021, CogView) applies LayerNorm both before the sub-layer (pre) and after the residual (post), combining the stability of pre-norm with some of the quality benefits of post-norm.

```python
import torch
import torch.nn as nn

class SandwichBlock(nn.Module):
    """Sandwich normalisation: LayerNorm before sublayer AND after residual.
    x_attn = LayerNorm_post(x + Attn(LayerNorm_pre(x)))
    x_ffn  = LayerNorm_post(x + FFN(LayerNorm_pre(x)))
    Reference: Ding et al. (2021) CogView.
    """
    def __init__(self, d_model: int, n_heads: int, d_ff: int):
        super().__init__()
        self.pre_attn  = nn.LayerNorm(d_model)
        self.post_attn = nn.LayerNorm(d_model)
        self.pre_ffn   = nn.LayerNorm(d_model)
        self.post_ffn  = nn.LayerNorm(d_model)
        self.attn = nn.MultiheadAttention(d_model, n_heads, batch_first=True)
        self.ff1  = nn.Linear(d_model, d_ff)
        self.ff2  = nn.Linear(d_ff, d_model)
        self.act  = nn.GELU()

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        # Attention with pre- and post-normalisation
        n = self.pre_attn(x)
        a, _ = self.attn(n, n, n)
        x = self.post_attn(x + a)
        # FFN with pre- and post-normalisation
        n = self.pre_ffn(x)
        x = self.post_ffn(x + self.ff2(self.act(self.ff1(n))))
        return x

torch.manual_seed(0)
d_model, n_heads, d_ff = 256, 8, 1024
inp   = torch.randn(2, 12, d_model)
block = SandwichBlock(d_model, n_heads, d_ff)
out   = block(inp)
print('Sandwich block output:', out.shape)
print('Input  mean norm:', inp.norm(dim=-1).mean().item())
print('Output mean norm:', out.norm(dim=-1).mean().item())
print('Params:', sum(p.numel() for p in block.parameters()))
```

## Pre-Norm vs Post-Norm at a Glance

| Property | Post-Norm (Vaswani 2017) | Pre-Norm (GPT-2, LLaMA) | Sandwich-Norm |
| --- | --- | --- | --- |
| LN position | After residual addition | Before sub-layer input | Before and after sub-layer |
| LR warmup needed | Yes — required to prevent divergence | No — more forgiving LR schedule | Minimal — stable at init |
| Gradient flow | Through LN Jacobian (unpredictable) | Residual bypasses LN (stable) | Mixed: pre and post paths |
| Convergence quality | Slightly better at final perplexity | Slightly lower but reliable | On par or better |
| Stability at 24+ layers | Difficult — common divergence | Good — default choice | Best reported stability |
| Modern adoption | T5, older BERT variants | GPT-2/3/4, LLaMA, Mistral, Gemma | CogView, specialised models |

For new Transformer architectures, pre-norm is the safe default: it trains without warmup, scales to hundreds of layers, and requires less careful learning-rate tuning. Post-norm may recover a small quality margin when training is carefully managed with warmup, and is worth considering for smaller models where training stability is less of a concern. Sandwich-norm offers a middle ground but adds extra parameters and is used primarily in large image-generation models.

