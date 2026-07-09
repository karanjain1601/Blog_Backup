---
title: "AdamW — Decoupled Weight Decay"
slug: "adamw-weight-decay"
description: "Rigorous analysis of why L2 regularization in standard Adam is corrupted by adaptive learning rates, AdamW's decoupled weight decay fix, and its role as the standard LLM optimizer."
tags: ["optimization", "regularization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Standard Adam with L2 regularization silently corrupts the regularization: the adaptive denominator sqrt(v_hat) scales each parameter's gradient differently, meaning L2 weight decay is applied non-uniformly — exactly the opposite of its intent. AdamW (Loshchilov & Hutter 2019) fixes this by decoupling weight decay from the gradient update. This insight makes AdamW the standard optimizer for training GPT, BERT, LLaMA, and virtually every large-scale language model. Understanding why Adam+L2 fails — and how AdamW fixes it — is essential for any practitioner training transformers at scale."}, {"type": "heading", "level": 2, "content": "The Problem: Adaptive Rates Corrupt L2 Regularization"}, {"type": "text", "content": "In vanilla SGD: L2 means adding lambda*theta to gradient, so effective update is theta <- theta*(1-eta*lambda) - eta*g. The L2 decay eta*lambda is applied uniformly across all parameters. In Adam: the effective gradient is g_eff = g + lambda*theta, which is then divided by sqrt(v_hat)+eps. The effective decay per parameter becomes eta*lambda*theta_i/(sqrt(v_hat_i)+eps) — it varies with gradient history. Parameters with large gradient history (large v_i) receive weaker L2 regularization. Parameters updated rarely (small v_i) receive stronger L2. This is the opposite of what L2 intends: it should penalize large weights uniformly, regardless of gradient history. The corruption is worst when gradient magnitudes vary widely across parameters — exactly the case in transformers."}, {"type": "code", "language": "python", "content": "import numpy as np\n\n# Show effective L2 decay per parameter for Adam+L2 vs AdamW\nnp.random.seed(42)\nn_params = 6\nlam = 0.01\nlr = 1e-3\n\n# Simulate diverse gradient histories\ntheta = np.ones(n_params) * 2.0\nv_hat = np.array([1e-4, 1e-3, 0.01, 0.1, 1.0, 10.0])  # range of second moments\neps = 1e-8\n\n# Adam+L2: effective decay = lr * lam / (sqrt(v_hat) + eps)\ng = np.ones(n_params) * 0.5   # uniform gradient\ng_l2 = g + lam * theta         # L2 adds lambda*theta to gradient\neff_decay_adam = lr * lam * theta / (np.sqrt(v_hat) + eps)\n\n# AdamW: effective decay = lr * lam (uniform)\neff_decay_adamw = np.full(n_params, lr * lam * theta[0])\n\nprint(f\"{'v_hat':>10} | {'Adam+L2 decay':>15} | {'AdamW decay':>12} | {'ratio':>8}\")\nprint(\"-\" * 55)\nfor i in range(n_params):\n    ratio = eff_decay_adam[i] / eff_decay_adamw[i]\n    print(f\"{v_hat[i]:>10.4f} | {eff_decay_adam[i]:>15.6f} | {eff_decay_adamw[i]:>12.6f} | {ratio:>8.4f}\")\nprint()\nprint(\"Adam+L2 decay varies 100x across params; AdamW is uniform.\")\n"}, {"type": "heading", "level": 2, "content": "AdamW: Decoupled Weight Decay"}, {"type": "text", "content": "AdamW (Loshchilov & Hutter 2019) decouples weight decay from the adaptive update: (1) compute gradient g_t without L2 term; (2) compute moment estimates m_t, v_t and bias-corrected m_hat_t, v_hat_t; (3) apply weight decay directly: theta_t = theta_{t-1}*(1 - alpha*lambda) - alpha*m_hat_t/(sqrt(v_hat_t)+eps). The decay alpha*lambda is uniform across all parameters regardless of gradient history. Weight decay for transformers: lambda=0.01 (BERT), lambda=0.1 (GPT-2), lambda=0.01-0.1 (LLaMA). Critically, embeddings and LayerNorm parameters are typically excluded from weight decay — they have no natural small-is-better prior, and shrinking them toward zero can destabilize normalization."}, {"type": "code", "language": "python", "content": "import torch\nimport numpy as np\n\ndef adamw_step(theta, g, m, v, t, lr=1e-3, b1=0.9, b2=0.999, eps=1e-8, wd=0.01):\n    # Step 1: compute gradient (no L2 term)\n    m = b1 * m + (1 - b1) * g\n    v = b2 * v + (1 - b2) * g ** 2\n    m_hat = m / (1 - b1 ** t)\n    v_hat = v / (1 - b2 ** t)\n    # Step 2: decoupled weight decay\n    theta = theta * (1 - lr * wd)\n    # Step 3: adaptive gradient update\n    theta = theta - lr * m_hat / (np.sqrt(v_hat) + eps)\n    return theta, m, v\n\n# Verify against torch.optim.AdamW\ntorch.manual_seed(0)\nmodel_param = torch.nn.Parameter(torch.tensor([2.0, -1.5, 0.8, -0.3]))\noptimizer = torch.optim.AdamW([model_param], lr=1e-3, weight_decay=0.01,\n                               betas=(0.9, 0.999), eps=1e-8)\n\ntheta_np = np.array([2.0, -1.5, 0.8, -0.3])\nm = v = np.zeros(4)\n\nfor t in range(1, 11):\n    grad_np = np.array([0.5, -0.3, 0.1, 0.8])\n    grad_t  = torch.tensor(grad_np)\n\n    optimizer.zero_grad()\n    model_param.grad = grad_t.clone()\n    optimizer.step()\n\n    theta_np, m, v = adamw_step(theta_np, grad_np, m, v, t)\n\nprint(\"PyTorch AdamW vs numpy AdamW after 10 steps:\")\nprint(f\"  PyTorch: {model_param.data.numpy().round(6)}\")\nprint(f\"  NumPy:   {theta_np.round(6)}\")\nprint(f\"  Max diff: {np.abs(model_param.data.numpy() - theta_np).max():.2e}\")\n"}, {"type": "heading", "level": 2, "content": "Which Parameters Get Weight Decay?"}, {"type": "text", "content": "Standard practice: apply weight decay to weight matrices (2D+ tensors) but not to biases or normalization parameters (LayerNorm gamma, beta; BatchNorm scale, shift). Rationale: weight decay shrinks weights toward zero, regularizing the function by reducing its effective norm. Biases and normalization parameters have no natural small-is-better prior — shrinking LayerNorm's gamma toward zero would collapse normalization. Excluding them avoids numerical issues with very small scale parameters. In code: create two parameter groups — one with weight_decay for weight matrices, one without for biases and normalization. This is the standard recipe in Hugging Face transformers and all major LLM training frameworks, and failure to do this correctly is a common source of subtle training instability."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn as nn\n\n# Standard transformer parameter grouping for AdamW\ndef get_param_groups(model, weight_decay=0.01):\n    decay_params    = []\n    no_decay_params = []\n    for name, param in model.named_parameters():\n        if not param.requires_grad:\n            continue\n        # weight matrices (2D+) get decay; biases and norms do not\n        if param.ndim >= 2 and 'weight' in name and 'norm' not in name:\n            decay_params.append(param)\n        else:\n            no_decay_params.append(param)\n    return [\n        {'params': decay_params,    'weight_decay': weight_decay},\n        {'params': no_decay_params, 'weight_decay': 0.0},\n    ]\n\ntorch.manual_seed(42)\nmodel = nn.Sequential(\n    nn.Linear(64, 128), nn.LayerNorm(128),\n    nn.Linear(128, 64), nn.LayerNorm(64),\n    nn.Linear(64, 10)\n)\ngroups = get_param_groups(model, weight_decay=0.01)\ndecay_count    = sum(p.numel() for p in groups[0]['params'])\nno_decay_count = sum(p.numel() for p in groups[1]['params'])\nprint(f\"Decay params:    {decay_count:,} ({len(groups[0]['params'])} tensors)\")\nprint(f\"No-decay params: {no_decay_count:,} ({len(groups[1]['params'])} tensors)\")\noptimizer = torch.optim.AdamW(groups, lr=3e-4)\nprint(f\"Optimizer: {optimizer.__class__.__name__} with {len(groups)} parameter groups\")\n"}, {"type": "heading", "level": 2, "content": "Lion and AdaFactor: Alternative Optimizers"}, {"type": "text", "content": "Recent AdamW alternatives address memory and efficiency. Lion (Chen 2023) uses sign(c_t) instead of the adaptive denominator, requiring only one momentum buffer vs Adam's two — 33% less optimizer memory. AdaFactor (Shazeer 2018) factorizes the second moment matrix: instead of storing v_ij (one value per weight), stores row and column sums, O(n+m) vs O(n*m) — enabling full-precision training of 10B+ models on limited GPU memory. Muon (Kostrikov 2024) applies Nesterov momentum and then orthogonalizes updates using Newton-Schulz iteration for matrix parameters, arguing that updates should preserve effective rank. All support decoupled weight decay. AdamW remains the default, but Lion and AdaFactor are compelling when memory is the binding constraint."}, {"type": "heading", "level": 2, "content": "ML Connections: LLM Training Practice"}, {"type": "text", "content": "AdamW with cosine LR schedule is the standard for pre-training LLMs. Typical recipe for a 7B parameter model: alpha=3e-4, beta1=0.9, beta2=0.95 (faster adaptation), eps=1e-8, lambda=0.1, warmup 1000 steps, cosine decay to 10% of peak LR. Beta2=0.95 rather than 0.999 is deliberate: with 0.999, second moment estimates take ~1000 steps to warm up; with 0.95, they warm up in ~20 steps — important for LLMs where gradient distribution shifts significantly during early training on diverse data. Weight decay 0.1 is larger than vision models because overparameterization is more extreme in LLMs. The Mistral and LLaMA training recipes both use this configuration with minor variations."}, {"type": "heading", "level": 2, "content": "Implementation Pitfalls"}, {"type": "text", "content": "Pitfall 1: applying weight decay to LayerNorm and embedding parameters — LayerNorm gamma and beta must have weight_decay=0 to avoid collapsing normalization scale. Pitfall 2: using torch.optim.Adam with weight_decay= instead of AdamW — many tutorials still do this, giving corrupted L2 regularization. Use torch.optim.AdamW always. Pitfall 3: not accounting for LR scaling — effective weight decay is alpha*lambda, not lambda alone. If cosine annealing halves LR by end of training, effective weight decay also halves. If constant regularization strength throughout training is desired, this must be explicitly compensated with a separate weight decay schedule or by using a constant LR with step-wise warmup."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Use AdamW for all transformer and large-scale neural network training. Standard parameter groups: params_decay = all weight matrices (ndim >= 2, 'norm' not in name), params_no_decay = biases and LayerNorm parameters. Weight decay lambda=0.01 for vision, 0.1 for language models. Monitor the ratio norm(delta_theta)/norm(theta) per layer: should be ~1e-3 for healthy training. If weight decay causes this ratio to drop below 1e-4 for some layers, reduce lambda or exclude those layers from decay. Always checkpoint the optimizer state alongside model weights to correctly resume training."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn as nn\n\n# AdamW training loop monitoring update-to-weight ratio per layer\ntorch.manual_seed(42)\n\ndef get_param_groups(model, wd=0.1):\n    decay, no_decay = [], []\n    for name, p in model.named_parameters():\n        if p.requires_grad:\n            (no_decay if (p.ndim < 2 or 'norm' in name) else decay).append(p)\n    return [{'params': decay, 'weight_decay': wd},\n            {'params': no_decay, 'weight_decay': 0.0}]\n\nmodel = nn.Sequential(\n    nn.Linear(32, 64), nn.LayerNorm(64), nn.ReLU(),\n    nn.Linear(64, 10)\n)\noptimizer = torch.optim.AdamW(get_param_groups(model, wd=0.1), lr=3e-4)\nscheduler = torch.optim.lr_scheduler.CosineAnnealingLR(optimizer, T_max=100)\n\nx = torch.randn(16, 32)\ny = torch.randint(0, 10, (16,))\n\nfor step in range(20):\n    old_params = {n: p.detach().clone() for n, p in model.named_parameters()}\n    optimizer.zero_grad()\n    loss = nn.CrossEntropyLoss()(model(x), y)\n    loss.backward()\n    torch.nn.utils.clip_grad_norm_(model.parameters(), 1.0)\n    optimizer.step()\n    scheduler.step()\n\n# Monitor update-to-weight ratio (should be ~1e-3 for healthy training)\nprint(\"Update-to-weight ratio per layer:\")\nfor name, p in model.named_parameters():\n    if p.requires_grad and old_params[name].norm() > 0:\n        ratio = (p.detach() - old_params[name]).norm() / old_params[name].norm()\n        print(f\"  {name:30s}: {ratio.item():.2e}\")\n"}, {"type": "callout", "title": "Effective Weight Decay Scales with Learning Rate", "content": "AdamW update: theta <- theta*(1 - alpha*lambda) - adaptive_update. The effective decay rate is alpha*lambda, not lambda alone. When using cosine annealing that reduces alpha by 10x, effective weight decay also falls 10x. If consistent regularization throughout training is desired, you must account for this: either use a constant LR with step decay, or implement a separate weight_decay schedule that compensates for LR changes. Some frameworks implement a normalized weight decay: lambda_eff = lambda / sqrt(T) where T is training steps."}, {"type": "table", "headers": ["Optimizer", "L2 Regularization", "Memory", "Convergence", "Best Use Case"], "rows": [["SGD+L2", "Correct uniform decay", "1 buffer/param", "O(kappa) steps", "Convex, image classification"], ["Adam+L2", "Corrupted (varies per param)", "2 buffers/param", "Fast (adaptive)", "Avoid for regularized training"], ["AdamW", "Correct decoupled decay", "2 buffers/param", "Fast (adaptive)", "Standard for LLMs, transformers"], ["AdaFactor+WD", "Correct decoupled decay", "O(n+m) factored", "Similar to AdamW", "Memory-constrained LLM training"], ["Lion+WD", "Correct decoupled decay", "1 buffer/param", "Comparable to AdamW", "Memory-efficient LLM training"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "items": ["Adam+L2 corrupts regularization: the adaptive denominator makes effective weight decay non-uniform, varying inversely with gradient history.", "AdamW decouples weight decay: apply theta*(1-alpha*lambda) before the adaptive update, giving uniform shrinkage across all parameters.", "Always exclude biases and LayerNorm parameters from weight decay — two parameter groups are required in any transformer training recipe.", "LLM standard: AdamW with beta2=0.95, weight_decay=0.1, warmup 1000 steps, cosine decay — not beta2=0.999 and not Adam.", "Effective weight decay = alpha*lambda; as LR decays via cosine annealing, effective regularization weakens correspondingly.", "Monitor update-to-weight ratio norm(delta_theta)/norm(theta) ~1e-3 per layer to verify healthy training dynamics."]}]"
---

# AdamW — Decoupled Weight Decay

Standard Adam with L2 regularization silently corrupts the regularization: the adaptive denominator sqrt(v_hat) scales each parameter's gradient differently, meaning L2 weight decay is applied non-uniformly — exactly the opposite of its intent. AdamW (Loshchilov & Hutter 2019) fixes this by decoupling weight decay from the gradient update. This insight makes AdamW the standard optimizer for training GPT, BERT, LLaMA, and virtually every large-scale language model. Understanding why Adam+L2 fails — and how AdamW fixes it — is essential for any practitioner training transformers at scale.

## The Problem: Adaptive Rates Corrupt L2 Regularization

In vanilla SGD: L2 means adding lambda*theta to gradient, so effective update is theta <- theta*(1-eta*lambda) - eta*g. The L2 decay eta*lambda is applied uniformly across all parameters. In Adam: the effective gradient is g_eff = g + lambda*theta, which is then divided by sqrt(v_hat)+eps. The effective decay per parameter becomes eta*lambda*theta_i/(sqrt(v_hat_i)+eps) — it varies with gradient history. Parameters with large gradient history (large v_i) receive weaker L2 regularization. Parameters updated rarely (small v_i) receive stronger L2. This is the opposite of what L2 intends: it should penalize large weights uniformly, regardless of gradient history. The corruption is worst when gradient magnitudes vary widely across parameters — exactly the case in transformers.

```python
import numpy as np

# Show effective L2 decay per parameter for Adam+L2 vs AdamW
np.random.seed(42)
n_params = 6
lam = 0.01
lr = 1e-3

# Simulate diverse gradient histories
theta = np.ones(n_params) * 2.0
v_hat = np.array([1e-4, 1e-3, 0.01, 0.1, 1.0, 10.0])  # range of second moments
eps = 1e-8

# Adam+L2: effective decay = lr * lam / (sqrt(v_hat) + eps)
g = np.ones(n_params) * 0.5   # uniform gradient
g_l2 = g + lam * theta         # L2 adds lambda*theta to gradient
eff_decay_adam = lr * lam * theta / (np.sqrt(v_hat) + eps)

# AdamW: effective decay = lr * lam (uniform)
eff_decay_adamw = np.full(n_params, lr * lam * theta[0])

print(f"{'v_hat':>10} | {'Adam+L2 decay':>15} | {'AdamW decay':>12} | {'ratio':>8}")
print("-" * 55)
for i in range(n_params):
    ratio = eff_decay_adam[i] / eff_decay_adamw[i]
    print(f"{v_hat[i]:>10.4f} | {eff_decay_adam[i]:>15.6f} | {eff_decay_adamw[i]:>12.6f} | {ratio:>8.4f}")
print()
print("Adam+L2 decay varies 100x across params; AdamW is uniform.")

```

## AdamW: Decoupled Weight Decay

AdamW (Loshchilov & Hutter 2019) decouples weight decay from the adaptive update: (1) compute gradient g_t without L2 term; (2) compute moment estimates m_t, v_t and bias-corrected m_hat_t, v_hat_t; (3) apply weight decay directly: theta_t = theta_{t-1}*(1 - alpha*lambda) - alpha*m_hat_t/(sqrt(v_hat_t)+eps). The decay alpha*lambda is uniform across all parameters regardless of gradient history. Weight decay for transformers: lambda=0.01 (BERT), lambda=0.1 (GPT-2), lambda=0.01-0.1 (LLaMA). Critically, embeddings and LayerNorm parameters are typically excluded from weight decay — they have no natural small-is-better prior, and shrinking them toward zero can destabilize normalization.

```python
import torch
import numpy as np

def adamw_step(theta, g, m, v, t, lr=1e-3, b1=0.9, b2=0.999, eps=1e-8, wd=0.01):
    # Step 1: compute gradient (no L2 term)
    m = b1 * m + (1 - b1) * g
    v = b2 * v + (1 - b2) * g ** 2
    m_hat = m / (1 - b1 ** t)
    v_hat = v / (1 - b2 ** t)
    # Step 2: decoupled weight decay
    theta = theta * (1 - lr * wd)
    # Step 3: adaptive gradient update
    theta = theta - lr * m_hat / (np.sqrt(v_hat) + eps)
    return theta, m, v

# Verify against torch.optim.AdamW
torch.manual_seed(0)
model_param = torch.nn.Parameter(torch.tensor([2.0, -1.5, 0.8, -0.3]))
optimizer = torch.optim.AdamW([model_param], lr=1e-3, weight_decay=0.01,
                               betas=(0.9, 0.999), eps=1e-8)

theta_np = np.array([2.0, -1.5, 0.8, -0.3])
m = v = np.zeros(4)

for t in range(1, 11):
    grad_np = np.array([0.5, -0.3, 0.1, 0.8])
    grad_t  = torch.tensor(grad_np)

    optimizer.zero_grad()
    model_param.grad = grad_t.clone()
    optimizer.step()

    theta_np, m, v = adamw_step(theta_np, grad_np, m, v, t)

print("PyTorch AdamW vs numpy AdamW after 10 steps:")
print(f"  PyTorch: {model_param.data.numpy().round(6)}")
print(f"  NumPy:   {theta_np.round(6)}")
print(f"  Max diff: {np.abs(model_param.data.numpy() - theta_np).max():.2e}")

```

## Which Parameters Get Weight Decay?

Standard practice: apply weight decay to weight matrices (2D+ tensors) but not to biases or normalization parameters (LayerNorm gamma, beta; BatchNorm scale, shift). Rationale: weight decay shrinks weights toward zero, regularizing the function by reducing its effective norm. Biases and normalization parameters have no natural small-is-better prior — shrinking LayerNorm's gamma toward zero would collapse normalization. Excluding them avoids numerical issues with very small scale parameters. In code: create two parameter groups — one with weight_decay for weight matrices, one without for biases and normalization. This is the standard recipe in Hugging Face transformers and all major LLM training frameworks, and failure to do this correctly is a common source of subtle training instability.

```python
import torch
import torch.nn as nn

# Standard transformer parameter grouping for AdamW
def get_param_groups(model, weight_decay=0.01):
    decay_params    = []
    no_decay_params = []
    for name, param in model.named_parameters():
        if not param.requires_grad:
            continue
        # weight matrices (2D+) get decay; biases and norms do not
        if param.ndim >= 2 and 'weight' in name and 'norm' not in name:
            decay_params.append(param)
        else:
            no_decay_params.append(param)
    return [
        {'params': decay_params,    'weight_decay': weight_decay},
        {'params': no_decay_params, 'weight_decay': 0.0},
    ]

torch.manual_seed(42)
model = nn.Sequential(
    nn.Linear(64, 128), nn.LayerNorm(128),
    nn.Linear(128, 64), nn.LayerNorm(64),
    nn.Linear(64, 10)
)
groups = get_param_groups(model, weight_decay=0.01)
decay_count    = sum(p.numel() for p in groups[0]['params'])
no_decay_count = sum(p.numel() for p in groups[1]['params'])
print(f"Decay params:    {decay_count:,} ({len(groups[0]['params'])} tensors)")
print(f"No-decay params: {no_decay_count:,} ({len(groups[1]['params'])} tensors)")
optimizer = torch.optim.AdamW(groups, lr=3e-4)
print(f"Optimizer: {optimizer.__class__.__name__} with {len(groups)} parameter groups")

```

## Lion and AdaFactor: Alternative Optimizers

Recent AdamW alternatives address memory and efficiency. Lion (Chen 2023) uses sign(c_t) instead of the adaptive denominator, requiring only one momentum buffer vs Adam's two — 33% less optimizer memory. AdaFactor (Shazeer 2018) factorizes the second moment matrix: instead of storing v_ij (one value per weight), stores row and column sums, O(n+m) vs O(n*m) — enabling full-precision training of 10B+ models on limited GPU memory. Muon (Kostrikov 2024) applies Nesterov momentum and then orthogonalizes updates using Newton-Schulz iteration for matrix parameters, arguing that updates should preserve effective rank. All support decoupled weight decay. AdamW remains the default, but Lion and AdaFactor are compelling when memory is the binding constraint.

## ML Connections: LLM Training Practice

AdamW with cosine LR schedule is the standard for pre-training LLMs. Typical recipe for a 7B parameter model: alpha=3e-4, beta1=0.9, beta2=0.95 (faster adaptation), eps=1e-8, lambda=0.1, warmup 1000 steps, cosine decay to 10% of peak LR. Beta2=0.95 rather than 0.999 is deliberate: with 0.999, second moment estimates take ~1000 steps to warm up; with 0.95, they warm up in ~20 steps — important for LLMs where gradient distribution shifts significantly during early training on diverse data. Weight decay 0.1 is larger than vision models because overparameterization is more extreme in LLMs. The Mistral and LLaMA training recipes both use this configuration with minor variations.

## Implementation Pitfalls

Pitfall 1: applying weight decay to LayerNorm and embedding parameters — LayerNorm gamma and beta must have weight_decay=0 to avoid collapsing normalization scale. Pitfall 2: using torch.optim.Adam with weight_decay= instead of AdamW — many tutorials still do this, giving corrupted L2 regularization. Use torch.optim.AdamW always. Pitfall 3: not accounting for LR scaling — effective weight decay is alpha*lambda, not lambda alone. If cosine annealing halves LR by end of training, effective weight decay also halves. If constant regularization strength throughout training is desired, this must be explicitly compensated with a separate weight decay schedule or by using a constant LR with step-wise warmup.

## Practical Guidance

Use AdamW for all transformer and large-scale neural network training. Standard parameter groups: params_decay = all weight matrices (ndim >= 2, 'norm' not in name), params_no_decay = biases and LayerNorm parameters. Weight decay lambda=0.01 for vision, 0.1 for language models. Monitor the ratio norm(delta_theta)/norm(theta) per layer: should be ~1e-3 for healthy training. If weight decay causes this ratio to drop below 1e-4 for some layers, reduce lambda or exclude those layers from decay. Always checkpoint the optimizer state alongside model weights to correctly resume training.

```python
import torch
import torch.nn as nn

# AdamW training loop monitoring update-to-weight ratio per layer
torch.manual_seed(42)

def get_param_groups(model, wd=0.1):
    decay, no_decay = [], []
    for name, p in model.named_parameters():
        if p.requires_grad:
            (no_decay if (p.ndim < 2 or 'norm' in name) else decay).append(p)
    return [{'params': decay, 'weight_decay': wd},
            {'params': no_decay, 'weight_decay': 0.0}]

model = nn.Sequential(
    nn.Linear(32, 64), nn.LayerNorm(64), nn.ReLU(),
    nn.Linear(64, 10)
)
optimizer = torch.optim.AdamW(get_param_groups(model, wd=0.1), lr=3e-4)
scheduler = torch.optim.lr_scheduler.CosineAnnealingLR(optimizer, T_max=100)

x = torch.randn(16, 32)
y = torch.randint(0, 10, (16,))

for step in range(20):
    old_params = {n: p.detach().clone() for n, p in model.named_parameters()}
    optimizer.zero_grad()
    loss = nn.CrossEntropyLoss()(model(x), y)
    loss.backward()
    torch.nn.utils.clip_grad_norm_(model.parameters(), 1.0)
    optimizer.step()
    scheduler.step()

# Monitor update-to-weight ratio (should be ~1e-3 for healthy training)
print("Update-to-weight ratio per layer:")
for name, p in model.named_parameters():
    if p.requires_grad and old_params[name].norm() > 0:
        ratio = (p.detach() - old_params[name]).norm() / old_params[name].norm()
        print(f"  {name:30s}: {ratio.item():.2e}")

```

> **Effective Weight Decay Scales with Learning Rate**: AdamW update: theta <- theta*(1 - alpha*lambda) - adaptive_update. The effective decay rate is alpha*lambda, not lambda alone. When using cosine annealing that reduces alpha by 10x, effective weight decay also falls 10x. If consistent regularization throughout training is desired, you must account for this: either use a constant LR with step decay, or implement a separate weight_decay schedule that compensates for LR changes. Some frameworks implement a normalized weight decay: lambda_eff = lambda / sqrt(T) where T is training steps.

| Optimizer | L2 Regularization | Memory | Convergence | Best Use Case |
|---|---|---|---|---|
| SGD+L2 | Correct uniform decay | 1 buffer/param | O(kappa) steps | Convex, image classification |
| Adam+L2 | Corrupted (varies per param) | 2 buffers/param | Fast (adaptive) | Avoid for regularized training |
| AdamW | Correct decoupled decay | 2 buffers/param | Fast (adaptive) | Standard for LLMs, transformers |
| AdaFactor+WD | Correct decoupled decay | O(n+m) factored | Similar to AdamW | Memory-constrained LLM training |
| Lion+WD | Correct decoupled decay | 1 buffer/param | Comparable to AdamW | Memory-efficient LLM training |

---

## Key Takeaways

- Adam+L2 corrupts regularization: the adaptive denominator makes effective weight decay non-uniform, varying inversely with gradient history.
- AdamW decouples weight decay: apply theta*(1-alpha*lambda) before the adaptive update, giving uniform shrinkage across all parameters.
- Always exclude biases and LayerNorm parameters from weight decay — two parameter groups are required in any transformer training recipe.
- LLM standard: AdamW with beta2=0.95, weight_decay=0.1, warmup 1000 steps, cosine decay — not beta2=0.999 and not Adam.
- Effective weight decay = alpha*lambda; as LR decays via cosine annealing, effective regularization weakens correspondingly.
- Monitor update-to-weight ratio norm(delta_theta)/norm(theta) ~1e-3 per layer to verify healthy training dynamics.

