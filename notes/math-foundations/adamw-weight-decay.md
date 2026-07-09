---
title: "AdamW — Decoupled Weight Decay"
slug: "adamw-weight-decay"
description: "Why adding L2 regularization to Adam is not equivalent to weight decay (the effective regularization is parameter-dependent), how AdamW decouples weight decay from the gradient update to achieve uniform regularization, and why this matters for transformer pretraining."
tags: ["calculus", "optimization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"The Problem with Adam + L2 Regularization"},{"type":"text","content":"The naive approach to regularization with Adam is to add λ‖θ‖² to the loss, which adds λθ to the gradient. Adam then scales this modified gradient by 1/√v̂, so the effective regularization for parameter i is λθ_i / √v̂_i. Parameters with large gradient variance (large v̂) receive weaker regularization than intended, while parameters with small gradient variance receive stronger regularization. This non-uniform effective regularization defeats the purpose of L2 and leads to worse generalization, especially for parameters in dense layers vs. sparse embedding layers."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\n\n# Demonstrate that Adam+L2 != weight decay\n# For Adam: effective L2 on param i = lambda / sqrt(v_hat_i)\n# For AdamW: effective weight decay = lambda (uniform)\n\nnp.random.seed(42)\n# Simulate two parameters: one with high gradient variance, one with low\nT = 100\nlambda_wd = 0.01\nbeta2, eps = 0.999, 1e-8\n\nv_high = 0.0   # tracks v for high-variance param\nv_low = 0.0    # tracks v for low-variance param\neff_l2_high, eff_l2_low = [], []\n\nfor t in range(1, T + 1):\n    g_high = 10.0 * np.random.randn()   # high gradient variance\n    g_low = 0.01 * np.random.randn()    # low gradient variance\n    v_high = beta2 * v_high + (1 - beta2) * g_high**2\n    v_low  = beta2 * v_low  + (1 - beta2) * g_low**2\n    v_hat_high = v_high / (1 - beta2**t)\n    v_hat_low  = v_low  / (1 - beta2**t)\n    # Effective L2 = lambda / sqrt(v_hat): smaller for high-variance params\n    eff_l2_high.append(lambda_wd / (np.sqrt(v_hat_high) + eps))\n    eff_l2_low.append(lambda_wd / (np.sqrt(v_hat_low) + eps))\n\nprint(f\u0027Effective L2 (high-var param): {np.mean(eff_l2_high[50:]):.6f}\u0027)\nprint(f\u0027Effective L2 (low-var  param): {np.mean(eff_l2_low[50:]):.6f}\u0027)\nprint(f\u0027AdamW weight decay (uniform):  {lambda_wd:.6f}\u0027)\nprint(\u0027Adam+L2 regularization is NON-UNIFORM; AdamW is UNIFORM\u0027)"},{"type":"heading","level":2,"content":"Decoupled Weight Decay in AdamW"},{"type":"text","content":"AdamW (Loshchilov \u0026 Hutter, 2019) decouples weight decay from the gradient update: θ_{t+1} = (1 − ηλ) θ_t − η m̂_t / (√v̂_t + ε). The weight decay term (1 − ηλ) is applied directly to the parameters, independently of the gradient magnitude. This gives every parameter the same fractional shrinkage ηλ per step, regardless of its gradient history. The gradient update m̂/(√v̂+ε) is unchanged from Adam and handles the adaptive scaling."},{"type":"callout","variant":"info","title":"AdamW is Now the Standard","content":"AdamW is the default optimizer for virtually all large transformer models: GPT-2/3/4, BERT, T5, LLaMA, and most modern vision transformers use AdamW with lr~3e-4 and weight decay~0.1. The difference from Adam+L2 is especially pronounced for embedding layers, which have sparse gradients and large v̂ — L2 barely affects them, while AdamW\u0027s decoupled decay regularizes them properly."},{"type":"heading","level":2,"content":"AdamW Implementation from Scratch"},{"type":"text","content":"AdamW differs from Adam in exactly one line: before the gradient update, the parameters are shrunk by the weight decay factor. The rest of the algorithm (moment updates, bias correction, adaptive scaling) is identical to Adam. This minimal change gives significantly better generalization in practice."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef adamw(grad_fn, x0, lr=0.001, beta1=0.9, beta2=0.999,\n          eps=1e-8, weight_decay=0.01, n_steps=500):\n    x = np.array(x0, dtype=float)\n    m = np.zeros_like(x)\n    v = np.zeros_like(x)\n    losses = [x[0]**2 + x[1]**2]   # toy loss = ||x||^2\n    for t in range(1, n_steps + 1):\n        g = grad_fn(x)\n        m = beta1 * m + (1 - beta1) * g\n        v = beta2 * v + (1 - beta2) * g**2\n        m_hat = m / (1 - beta1**t)\n        v_hat = v / (1 - beta2**t)\n        # Decoupled weight decay: applied directly to params (not via gradient)\n        x = x * (1 - lr * weight_decay)\n        x = x - lr * m_hat / (np.sqrt(v_hat) + eps)\n        losses.append(x[0]**2 + x[1]**2)\n    return x, losses\n\ndef adam_l2(grad_fn_base, x0, lr=0.001, beta1=0.9, beta2=0.999,\n            eps=1e-8, weight_decay=0.01, n_steps=500):\n    x = np.array(x0, dtype=float)\n    m, v = np.zeros_like(x), np.zeros_like(x)\n    losses = [x[0]**2 + x[1]**2]\n    for t in range(1, n_steps + 1):\n        # L2 adds wd*x to gradient (coupled to adaptive scaling)\n        g = grad_fn_base(x) + weight_decay * x\n        m = beta1 * m + (1 - beta1) * g\n        v = beta2 * v + (1 - beta2) * g**2\n        m_hat = m / (1 - beta1**t)\n        v_hat = v / (1 - beta2**t)\n        x = x - lr * m_hat / (np.sqrt(v_hat) + eps)\n        losses.append(x[0]**2 + x[1]**2)\n    return x, losses\n\ngrad_fn = lambda x: np.array([2*x[0], 100*x[1]])  # ill-conditioned\nx_adamw, l_adamw = adamw(grad_fn, [3.0, 2.0], lr=0.05, weight_decay=0.1)\nx_adam2, l_adam2 = adam_l2(grad_fn, [3.0, 2.0], lr=0.05, weight_decay=0.1)\nplt.figure(figsize=(8, 3))\nplt.semilogy(l_adamw, label=\u0027AdamW (decoupled WD)\u0027)\nplt.semilogy(l_adam2, label=\u0027Adam + L2 (coupled WD)\u0027)\nplt.xlabel(\u0027Step\u0027); plt.ylabel(\u0027||x||^2\u0027); plt.legend()\nplt.title(\u0027AdamW vs Adam+L2: Decoupled vs Coupled Weight Decay\u0027)\nplt.grid(True, alpha=0.3); plt.tight_layout()\nplt.savefig(\u0027adamw_vs_adam.png\u0027, dpi=150); plt.show()"},{"type":"heading","level":2,"content":"Why This Matters in Practice"},{"type":"text","content":"Empirically, AdamW outperforms Adam+L2 on language model pretraining by 1–2 perplexity points with the same hyperparameters, and the difference grows with model scale. The key affected parameters are: (1) embedding layers — sparse gradients give large v̂, so L2 is nearly zero for them; (2) LayerNorm gains and biases — small gradients, so Adam+L2 over-regularizes them. Standard practice: apply weight decay to all parameters except LayerNorm, biases, and embedding norms."},{"type":"heading","level":2,"content":"Weight Decay as Gaussian Prior (MAP Perspective)"},{"type":"text","content":"Weight decay has a Bayesian interpretation: minimizing L(θ) + (λ/2)‖θ‖² is equivalent to Maximum A Posteriori (MAP) estimation with a Gaussian prior θ ~ N(0, 1/λ ⋅ I). The L2 penalty shrinks weights toward zero, which regularizes by preferring smaller weights. This MAP interpretation makes it clear that weight decay (not L2 regularization coupled into the gradient) is the principled regularizer for Bayesian deep learning."},{"type":"heading","level":2,"content":"Typical Hyperparameters for Transformers"},{"type":"text","content":"Standard AdamW settings for transformer pretraining: lr=3e-4 (with cosine decay), β₁=0.9, β₂=0.95 (slightly lower than default 0.999 for better adaptation to gradient changes), ε=1e-8, weight_decay=0.1. Weight decay=0.1 is much larger than the L2 penalty typically used with SGD (0.0001–0.001) because AdamW\u0027s decoupled decay does not interact with the adaptive scaling. Some recipes use weight_decay=0.01 for smaller models."},{"type":"table","headers":["Setting","Adam + L2 loss","AdamW (decoupled WD)","Recommendation"],"rows":[["Dense layer weights","L2 scaled by 1/sqrt(v̂) — near-uniform for dense grads","Uniform decay λη per step","Use AdamW; dense params benefit equally"],["Embedding weights (sparse)","Very weak L2 (large v̂ from occasional large grads)","Uniform decay λη per step","AdamW critical; L2 barely regularizes these"],["LayerNorm / biases","L2 applied; small v̂ → over-regularized","Should be excluded from WD","Exclude from WD in both; AdamW makes exclusion critical"],["Output projection","L2 scaled by gradient magnitude history","Uniform decay","Use AdamW for consistent regularization"]]},{"type":"heading","level":2,"content":"Training a Transformer Block with AdamW"},{"type":"text","content":"When using AdamW for transformer training, it\u0027s important to exclude certain parameter groups from weight decay. LayerNorm parameters, biases, and sometimes position embeddings should have weight_decay=0.0 to avoid over-regularizing them. PyTorch makes this easy with parameter groups in the optimizer. Below is a practical setup for a simple transformer block."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\nimport matplotlib.pyplot as plt\n\ntorch.manual_seed(42)\n\nclass TransformerBlock(nn.Module):\n    def __init__(self, d_model=64, n_heads=4):\n        super().__init__()\n        self.attn = nn.MultiheadAttention(d_model, n_heads, batch_first=True)\n        self.ff = nn.Sequential(nn.Linear(d_model, 256), nn.GELU(), nn.Linear(256, d_model))\n        self.ln1 = nn.LayerNorm(d_model)\n        self.ln2 = nn.LayerNorm(d_model)\n\n    def forward(self, x):\n        x = x + self.attn(self.ln1(x), self.ln1(x), self.ln1(x))[0]\n        x = x + self.ff(self.ln2(x))\n        return x\n\nmodel = TransformerBlock()\n# Separate param groups: no WD for LN params and biases\nno_decay = [\u0027bias\u0027, \u0027weight\u0027] if False else []\ndecay_params = [p for n, p in model.named_parameters() if not any(nd in n for nd in [\u0027ln\u0027, \u0027bias\u0027])]\nno_decay_params = [p for n, p in model.named_parameters() if any(nd in n for nd in [\u0027ln\u0027, \u0027bias\u0027])]\noptimizer = optim.AdamW([\n    {\u0027params\u0027: decay_params, \u0027weight_decay\u0027: 0.1},\n    {\u0027params\u0027: no_decay_params, \u0027weight_decay\u0027: 0.0}\n], lr=3e-4, betas=(0.9, 0.95), eps=1e-8)\n\nX = torch.randn(8, 16, 64)  # batch=8, seq_len=16, d_model=64\nlosses = []\nfor step in range(100):\n    out = model(X)\n    loss = out.pow(2).mean()  # toy loss\n    optimizer.zero_grad(); loss.backward(); optimizer.step()\n    losses.append(loss.item())\nprint(f\u0027Decay params: {len(decay_params)}, No-decay params: {len(no_decay_params)}\u0027)\nprint(f\u0027Final loss: {losses[-1]:.4f}\u0027)"},{"type":"heading","level":2,"content":"Combined LR and Weight Decay Schedule"},{"type":"text","content":"Modern transformer training uses cosine learning rate decay with linear warmup, combined with constant weight decay. Some recipes also apply cosine decay to the weight decay itself (starting high and ending low). The warmup period (typically 1–5% of total steps) prevents instability from Adam\u0027s unreliable second moment estimate at initialization. After warmup, the cosine decay smoothly reduces the learning rate to a minimum (typically lr_min = lr_max/10)."},{"type":"code","language":"python","content":"import torch\nimport torch.optim as optim\nimport math\nimport matplotlib.pyplot as plt\n\ntorch.manual_seed(42)\nmodel = torch.nn.Linear(64, 64)\noptimizer = optim.AdamW(model.parameters(), lr=3e-4, weight_decay=0.1, betas=(0.9, 0.95))\n\ntotal_steps = 1000\nwarmup_steps = 100\nlr_max = 3e-4\nlr_min = 3e-5\n\ndef get_lr(step):\n    if step \u003c warmup_steps:\n        return lr_max * step / warmup_steps  # linear warmup\n    progress = (step - warmup_steps) / (total_steps - warmup_steps)\n    return lr_min + 0.5 * (lr_max - lr_min) * (1 + math.cos(math.pi * progress))\n\nlr_schedule = [get_lr(s) for s in range(total_steps)]\nlosses = []\nfor step in range(total_steps):\n    lr = get_lr(step)\n    for pg in optimizer.param_groups:\n        pg[\u0027lr\u0027] = lr\n    x = torch.randn(16, 64)\n    loss = model(x).pow(2).mean()\n    optimizer.zero_grad(); loss.backward(); optimizer.step()\n    losses.append(loss.item())\n\nfig, axes = plt.subplots(1, 2, figsize=(11, 3))\naxes[0].plot(lr_schedule); axes[0].set_title(\u0027LR Schedule: Warmup + Cosine Decay\u0027)\naxes[0].set_xlabel(\u0027Step\u0027); axes[0].set_ylabel(\u0027Learning Rate\u0027)\naxes[1].plot(losses); axes[1].set_title(\u0027Training Loss\u0027)\naxes[1].set_xlabel(\u0027Step\u0027); axes[1].set_ylabel(\u0027Loss\u0027)\nplt.tight_layout(); plt.savefig(\u0027adamw_schedule.png\u0027, dpi=150); plt.show()"},{"type":"list","ordered":false,"items":["Adam+L2 gives non-uniform effective regularization: λθ_i / sqrt(v̂_i)","AdamW decouples: applies (1-ηλ) shrinkage directly to params, independent of v̂","Uniform λ for all params, regardless of gradient magnitude history","Exclude LayerNorm weights and biases from weight decay (param groups)","Use weight_decay=0.1 for transformers with AdamW (much higher than SGD L2 setting)"]},{"type":"callout","variant":"tip","title":"AdamW Recipe for Transformers","content":"Use AdamW with lr=3e-4, β₁=0.9, β₂=0.95 (not 0.999), eps=1e-8, weight_decay=0.1. Use linear warmup for 1–2% of total steps then cosine decay. Exclude biases and LayerNorm parameters from weight decay. Gradient clip to max norm 1.0. These settings work well for GPT-style models from 100M to 7B parameters without significant tuning."},{"type":"divider"}]"
---
# AdamW — Decoupled Weight Decay

## The Problem with Adam + L2 Regularization

The naive approach to regularization with Adam is to add λ‖θ‖² to the loss, which adds λθ to the gradient. Adam then scales this modified gradient by 1/√v̂, so the effective regularization for parameter i is λθ_i / √v̂_i. Parameters with large gradient variance (large v̂) receive weaker regularization than intended, while parameters with small gradient variance receive stronger regularization. This non-uniform effective regularization defeats the purpose of L2 and leads to worse generalization, especially for parameters in dense layers vs. sparse embedding layers.

```python
import numpy as np
import torch

# Demonstrate that Adam+L2 != weight decay
# For Adam: effective L2 on param i = lambda / sqrt(v_hat_i)
# For AdamW: effective weight decay = lambda (uniform)

np.random.seed(42)
# Simulate two parameters: one with high gradient variance, one with low
T = 100
lambda_wd = 0.01
beta2, eps = 0.999, 1e-8

v_high = 0.0   # tracks v for high-variance param
v_low = 0.0    # tracks v for low-variance param
eff_l2_high, eff_l2_low = [], []

for t in range(1, T + 1):
    g_high = 10.0 * np.random.randn()   # high gradient variance
    g_low = 0.01 * np.random.randn()    # low gradient variance
    v_high = beta2 * v_high + (1 - beta2) * g_high**2
    v_low  = beta2 * v_low  + (1 - beta2) * g_low**2
    v_hat_high = v_high / (1 - beta2**t)
    v_hat_low  = v_low  / (1 - beta2**t)
    # Effective L2 = lambda / sqrt(v_hat): smaller for high-variance params
    eff_l2_high.append(lambda_wd / (np.sqrt(v_hat_high) + eps))
    eff_l2_low.append(lambda_wd / (np.sqrt(v_hat_low) + eps))

print(f'Effective L2 (high-var param): {np.mean(eff_l2_high[50:]):.6f}')
print(f'Effective L2 (low-var  param): {np.mean(eff_l2_low[50:]):.6f}')
print(f'AdamW weight decay (uniform):  {lambda_wd:.6f}')
print('Adam+L2 regularization is NON-UNIFORM; AdamW is UNIFORM')
```

## Decoupled Weight Decay in AdamW

AdamW (Loshchilov & Hutter, 2019) decouples weight decay from the gradient update: θ_{t+1} = (1 − ηλ) θ_t − η m̂_t / (√v̂_t + ε). The weight decay term (1 − ηλ) is applied directly to the parameters, independently of the gradient magnitude. This gives every parameter the same fractional shrinkage ηλ per step, regardless of its gradient history. The gradient update m̂/(√v̂+ε) is unchanged from Adam and handles the adaptive scaling.

> **AdamW is Now the Standard**: AdamW is the default optimizer for virtually all large transformer models: GPT-2/3/4, BERT, T5, LLaMA, and most modern vision transformers use AdamW with lr~3e-4 and weight decay~0.1. The difference from Adam+L2 is especially pronounced for embedding layers, which have sparse gradients and large v̂ — L2 barely affects them, while AdamW's decoupled decay regularizes them properly.

## AdamW Implementation from Scratch

AdamW differs from Adam in exactly one line: before the gradient update, the parameters are shrunk by the weight decay factor. The rest of the algorithm (moment updates, bias correction, adaptive scaling) is identical to Adam. This minimal change gives significantly better generalization in practice.

```python
import numpy as np
import matplotlib.pyplot as plt

def adamw(grad_fn, x0, lr=0.001, beta1=0.9, beta2=0.999,
          eps=1e-8, weight_decay=0.01, n_steps=500):
    x = np.array(x0, dtype=float)
    m = np.zeros_like(x)
    v = np.zeros_like(x)
    losses = [x[0]**2 + x[1]**2]   # toy loss = ||x||^2
    for t in range(1, n_steps + 1):
        g = grad_fn(x)
        m = beta1 * m + (1 - beta1) * g
        v = beta2 * v + (1 - beta2) * g**2
        m_hat = m / (1 - beta1**t)
        v_hat = v / (1 - beta2**t)
        # Decoupled weight decay: applied directly to params (not via gradient)
        x = x * (1 - lr * weight_decay)
        x = x - lr * m_hat / (np.sqrt(v_hat) + eps)
        losses.append(x[0]**2 + x[1]**2)
    return x, losses

def adam_l2(grad_fn_base, x0, lr=0.001, beta1=0.9, beta2=0.999,
            eps=1e-8, weight_decay=0.01, n_steps=500):
    x = np.array(x0, dtype=float)
    m, v = np.zeros_like(x), np.zeros_like(x)
    losses = [x[0]**2 + x[1]**2]
    for t in range(1, n_steps + 1):
        # L2 adds wd*x to gradient (coupled to adaptive scaling)
        g = grad_fn_base(x) + weight_decay * x
        m = beta1 * m + (1 - beta1) * g
        v = beta2 * v + (1 - beta2) * g**2
        m_hat = m / (1 - beta1**t)
        v_hat = v / (1 - beta2**t)
        x = x - lr * m_hat / (np.sqrt(v_hat) + eps)
        losses.append(x[0]**2 + x[1]**2)
    return x, losses

grad_fn = lambda x: np.array([2*x[0], 100*x[1]])  # ill-conditioned
x_adamw, l_adamw = adamw(grad_fn, [3.0, 2.0], lr=0.05, weight_decay=0.1)
x_adam2, l_adam2 = adam_l2(grad_fn, [3.0, 2.0], lr=0.05, weight_decay=0.1)
plt.figure(figsize=(8, 3))
plt.semilogy(l_adamw, label='AdamW (decoupled WD)')
plt.semilogy(l_adam2, label='Adam + L2 (coupled WD)')
plt.xlabel('Step'); plt.ylabel('||x||^2'); plt.legend()
plt.title('AdamW vs Adam+L2: Decoupled vs Coupled Weight Decay')
plt.grid(True, alpha=0.3); plt.tight_layout()
plt.savefig('adamw_vs_adam.png', dpi=150); plt.show()
```

## Why This Matters in Practice

Empirically, AdamW outperforms Adam+L2 on language model pretraining by 1–2 perplexity points with the same hyperparameters, and the difference grows with model scale. The key affected parameters are: (1) embedding layers — sparse gradients give large v̂, so L2 is nearly zero for them; (2) LayerNorm gains and biases — small gradients, so Adam+L2 over-regularizes them. Standard practice: apply weight decay to all parameters except LayerNorm, biases, and embedding norms.

## Weight Decay as Gaussian Prior (MAP Perspective)

Weight decay has a Bayesian interpretation: minimizing L(θ) + (λ/2)‖θ‖² is equivalent to Maximum A Posteriori (MAP) estimation with a Gaussian prior θ ~ N(0, 1/λ ⋅ I). The L2 penalty shrinks weights toward zero, which regularizes by preferring smaller weights. This MAP interpretation makes it clear that weight decay (not L2 regularization coupled into the gradient) is the principled regularizer for Bayesian deep learning.

## Typical Hyperparameters for Transformers

Standard AdamW settings for transformer pretraining: lr=3e-4 (with cosine decay), β₁=0.9, β₂=0.95 (slightly lower than default 0.999 for better adaptation to gradient changes), ε=1e-8, weight_decay=0.1. Weight decay=0.1 is much larger than the L2 penalty typically used with SGD (0.0001–0.001) because AdamW's decoupled decay does not interact with the adaptive scaling. Some recipes use weight_decay=0.01 for smaller models.

| Setting | Adam + L2 loss | AdamW (decoupled WD) | Recommendation |
| --- | --- | --- | --- |
| Dense layer weights | L2 scaled by 1/sqrt(v̂) — near-uniform for dense grads | Uniform decay λη per step | Use AdamW; dense params benefit equally |
| Embedding weights (sparse) | Very weak L2 (large v̂ from occasional large grads) | Uniform decay λη per step | AdamW critical; L2 barely regularizes these |
| LayerNorm / biases | L2 applied; small v̂ → over-regularized | Should be excluded from WD | Exclude from WD in both; AdamW makes exclusion critical |
| Output projection | L2 scaled by gradient magnitude history | Uniform decay | Use AdamW for consistent regularization |

## Training a Transformer Block with AdamW

When using AdamW for transformer training, it's important to exclude certain parameter groups from weight decay. LayerNorm parameters, biases, and sometimes position embeddings should have weight_decay=0.0 to avoid over-regularizing them. PyTorch makes this easy with parameter groups in the optimizer. Below is a practical setup for a simple transformer block.

```python
import torch
import torch.nn as nn
import torch.optim as optim
import matplotlib.pyplot as plt

torch.manual_seed(42)

class TransformerBlock(nn.Module):
    def __init__(self, d_model=64, n_heads=4):
        super().__init__()
        self.attn = nn.MultiheadAttention(d_model, n_heads, batch_first=True)
        self.ff = nn.Sequential(nn.Linear(d_model, 256), nn.GELU(), nn.Linear(256, d_model))
        self.ln1 = nn.LayerNorm(d_model)
        self.ln2 = nn.LayerNorm(d_model)

    def forward(self, x):
        x = x + self.attn(self.ln1(x), self.ln1(x), self.ln1(x))[0]
        x = x + self.ff(self.ln2(x))
        return x

model = TransformerBlock()
# Separate param groups: no WD for LN params and biases
no_decay = ['bias', 'weight'] if False else []
decay_params = [p for n, p in model.named_parameters() if not any(nd in n for nd in ['ln', 'bias'])]
no_decay_params = [p for n, p in model.named_parameters() if any(nd in n for nd in ['ln', 'bias'])]
optimizer = optim.AdamW([
    {'params': decay_params, 'weight_decay': 0.1},
    {'params': no_decay_params, 'weight_decay': 0.0}
], lr=3e-4, betas=(0.9, 0.95), eps=1e-8)

X = torch.randn(8, 16, 64)  # batch=8, seq_len=16, d_model=64
losses = []
for step in range(100):
    out = model(X)
    loss = out.pow(2).mean()  # toy loss
    optimizer.zero_grad(); loss.backward(); optimizer.step()
    losses.append(loss.item())
print(f'Decay params: {len(decay_params)}, No-decay params: {len(no_decay_params)}')
print(f'Final loss: {losses[-1]:.4f}')
```

## Combined LR and Weight Decay Schedule

Modern transformer training uses cosine learning rate decay with linear warmup, combined with constant weight decay. Some recipes also apply cosine decay to the weight decay itself (starting high and ending low). The warmup period (typically 1–5% of total steps) prevents instability from Adam's unreliable second moment estimate at initialization. After warmup, the cosine decay smoothly reduces the learning rate to a minimum (typically lr_min = lr_max/10).

```python
import torch
import torch.optim as optim
import math
import matplotlib.pyplot as plt

torch.manual_seed(42)
model = torch.nn.Linear(64, 64)
optimizer = optim.AdamW(model.parameters(), lr=3e-4, weight_decay=0.1, betas=(0.9, 0.95))

total_steps = 1000
warmup_steps = 100
lr_max = 3e-4
lr_min = 3e-5

def get_lr(step):
    if step < warmup_steps:
        return lr_max * step / warmup_steps  # linear warmup
    progress = (step - warmup_steps) / (total_steps - warmup_steps)
    return lr_min + 0.5 * (lr_max - lr_min) * (1 + math.cos(math.pi * progress))

lr_schedule = [get_lr(s) for s in range(total_steps)]
losses = []
for step in range(total_steps):
    lr = get_lr(step)
    for pg in optimizer.param_groups:
        pg['lr'] = lr
    x = torch.randn(16, 64)
    loss = model(x).pow(2).mean()
    optimizer.zero_grad(); loss.backward(); optimizer.step()
    losses.append(loss.item())

fig, axes = plt.subplots(1, 2, figsize=(11, 3))
axes[0].plot(lr_schedule); axes[0].set_title('LR Schedule: Warmup + Cosine Decay')
axes[0].set_xlabel('Step'); axes[0].set_ylabel('Learning Rate')
axes[1].plot(losses); axes[1].set_title('Training Loss')
axes[1].set_xlabel('Step'); axes[1].set_ylabel('Loss')
plt.tight_layout(); plt.savefig('adamw_schedule.png', dpi=150); plt.show()
```

- Adam+L2 gives non-uniform effective regularization: λθ_i / sqrt(v̂_i)
- AdamW decouples: applies (1-ηλ) shrinkage directly to params, independent of v̂
- Uniform λ for all params, regardless of gradient magnitude history
- Exclude LayerNorm weights and biases from weight decay (param groups)
- Use weight_decay=0.1 for transformers with AdamW (much higher than SGD L2 setting)

> **AdamW Recipe for Transformers**: Use AdamW with lr=3e-4, β₁=0.9, β₂=0.95 (not 0.999), eps=1e-8, weight_decay=0.1. Use linear warmup for 1–2% of total steps then cosine decay. Exclude biases and LayerNorm parameters from weight decay. Gradient clip to max norm 1.0. These settings work well for GPT-style models from 100M to 7B parameters without significant tuning.

---

