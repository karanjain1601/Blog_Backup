---
title: "Exploding Gradients — Clipping Strategies"
slug: "exploding-gradients-clipping"
description: "Understand why gradients explode in RNNs and deep networks, compare value vs norm clipping empirically, monitor gradient health during training, and apply correct clipping with gradient accumulation."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Exploding gradients are the opposite of vanishing: when the spectral radius of each Jacobian exceeds 1, the product of Jacobians grows exponentially with depth or sequence length. RNNs are especially vulnerable because the same weight matrix W is multiplied at every time step — the effective depth equals the sequence length, which can be hundreds or thousands. Symptoms include NaN loss, diverging training curves, and sudden gradient norm spikes."},{"type":"text","content":"Two main clipping strategies exist: value clipping (per-element) and norm clipping (global scale). Norm clipping is the standard for large language models. Exploding gradients are distinct from vanishing — both can coexist in the same network when early layers vanish and late layers explode, a common pathology in very deep networks without residual connections."},{"type":"heading","level":2,"content":"Mathematical Cause — RNN Gradient Explosion"},{"type":"text","content":"In an RNN, hₜ = tanh(Whₜ₋₁ + Uxₜ). By the chain rule, ∂hₜ/∂h₀ = Πₖ₌₁ᵗ diag(tanh\u0027(·)) · W. If ρ(W) \u003e 1, then ‖∂hₜ/∂h₀‖ grows as ρ(W)ᵀ. For ρ(W) = 1.1 and T=100, gradient magnitude reaches 1.1¹⁰⁰ ≈ 13,780. Even modest spectral radii above 1 produce catastrophic explosion over long sequences."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef simulate_explosion(seq_len=50, hidden=32, spectral_radius=1.1, seed=0):\n    torch.manual_seed(seed)\n    rnn = nn.RNNCell(hidden, hidden, nonlinearity=\u0027tanh\u0027)\n    with torch.no_grad():\n        U, S, V = torch.linalg.svd(rnn.weight_hh)\n        rnn.weight_hh.data = (U * (S * spectral_radius / S[0]).unsqueeze(0)) @ V\n    h = torch.zeros(1, hidden, requires_grad=True)\n    h_curr = h\n    for t in range(seq_len):\n        h_curr = rnn(torch.randn(1, hidden), h_curr)\n    h_curr.mean().backward()\n    print(f\u0027rho={spectral_radius}, T={seq_len}: grad norm={h.grad.norm():.3e}, expected~{spectral_radius**seq_len:.3e}\u0027)\n\nsimulate_explosion(seq_len=30, spectral_radius=1.05)\nsimulate_explosion(seq_len=30, spectral_radius=1.20)"},{"type":"heading","level":2,"content":"Value Clipping vs Norm Clipping"},{"type":"text","content":"Value clipping clips each gradient element independently: gᵢ ← clip(gᵢ, −c, c). This changes the gradient direction — relative magnitudes across parameters are altered. Norm clipping rescales the entire gradient: if ‖g‖ \u003e c, then g ← g · c/‖g‖. This preserves direction while bounding magnitude. Norm clipping is the standard in LLM training — GPT, T5, LLaMA all use max_norm=1.0."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef compare_clipping(clip_val=1.0):\n    torch.manual_seed(7)\n    model = nn.Linear(10, 10)\n    (model(torch.randn(4, 10)) * 100).mean().backward()\n    g_orig = model.weight.grad.clone()\n    orig_dir = F.normalize(g_orig.flatten(), dim=0)\n\n    model.weight.grad.data = g_orig.clone()\n    torch.nn.utils.clip_grad_value_(model.parameters(), clip_value=clip_val)\n    cos_value = (orig_dir * F.normalize(model.weight.grad.flatten(), dim=0)).sum().item()\n\n    model.weight.grad.data = g_orig.clone()\n    torch.nn.utils.clip_grad_norm_(model.parameters(), max_norm=clip_val)\n    cos_norm  = (orig_dir * F.normalize(model.weight.grad.flatten(), dim=0)).sum().item()\n\n    print(f\u0027Original norm: {g_orig.norm():.4f}\u0027)\n    print(f\u0027Value clip cosine sim: {cos_value:.6f}\u0027)\n    print(f\u0027Norm  clip cosine sim: {cos_norm:.6f}\u0027)\n    print(\u0027Norm clipping preserves direction (cos≈1); value clipping distorts it.\u0027)\n\ncompare_clipping()"},{"type":"heading","level":2,"content":"Gradient Norm Monitoring During Training"},{"type":"text","content":"Logging the pre-clip gradient norm every step is the primary health metric for deep network training. A healthy norm stays in a stable range; spikes indicate instability. If more than 30% of steps require clipping, the learning rate is too high. If gradient norms are consistently near zero in early layers, vanishing is the issue — clipping cannot fix vanishing gradients."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef train_with_grad_monitoring(n_steps=200, clip=1.0, seed=0):\n    torch.manual_seed(seed)\n    model = nn.Sequential(\n        nn.Linear(64, 256), nn.Tanh(),\n        nn.Linear(256, 256), nn.Tanh(),\n        nn.Linear(256, 10)\n    )\n    optimizer = torch.optim.Adam(model.parameters(), lr=1e-3)\n    grad_norms, clipped = [], 0\n    for step in range(n_steps):\n        x, y = torch.randn(32, 64), torch.randint(0, 10, (32,))\n        nn.CrossEntropyLoss()(model(x), y).backward()\n        total_norm = torch.nn.utils.clip_grad_norm_(model.parameters(), max_norm=clip)\n        grad_norms.append(total_norm.item())\n        if total_norm.item() \u003e clip: clipped += 1\n        optimizer.step(); optimizer.zero_grad()\n    print(f\u0027Clip={clip}: {clipped}/{n_steps} steps clipped ({100*clipped/n_steps:.1f}%)\u0027)\n    print(f\u0027Grad norm: mean={np.mean(grad_norms):.4f} max={np.max(grad_norms):.4f}\u0027)\n\ntrain_with_grad_monitoring(clip=1.0)"},{"type":"heading","level":2,"content":"Gradient Accumulation with Correct Clipping"},{"type":"text","content":"Gradient accumulation simulates a larger effective batch size by accumulating gradients over multiple micro-steps before calling optimizer.step(). The critical rule: clip after all micro-steps, never before. Clipping each micro-batch independently applies multiple clipping operations and the final gradient does not correspond to a single clipped global gradient. Scale the loss by 1/accum_steps before backward to normalize the accumulated gradient."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef train_with_accumulation(accum_steps=4, clip=1.0, n_iters=50):\n    torch.manual_seed(0)\n    model = nn.Sequential(nn.Linear(32, 64), nn.ReLU(), nn.Linear(64, 4))\n    optimizer = torch.optim.AdamW(model.parameters(), lr=1e-3)\n    criterion = nn.CrossEntropyLoss()\n    for step in range(n_iters):\n        optimizer.zero_grad()\n        total_loss = 0.0\n        for _ in range(accum_steps):\n            x = torch.randn(8, 32)\n            y = torch.randint(0, 4, (8,))\n            loss = criterion(model(x), y) / accum_steps\n            loss.backward()\n            total_loss += loss.item()\n        grad_norm = torch.nn.utils.clip_grad_norm_(model.parameters(), max_norm=clip)\n        optimizer.step()\n        if step % 10 == 0:\n            print(f\u0027Step {step:3d}: loss={total_loss:.4f} grad_norm={grad_norm:.4f}\u0027)\n\ntrain_with_accumulation()"},{"type":"heading","level":2,"content":"LR Warmup and Spectral Normalization"},{"type":"text","content":"Learning rate warmup linearly increases LR from 0 to the target over the first few hundred steps. At the start of training, parameters are randomly initialized and gradients can be large and inconsistent. A small initial LR prevents early gradient explosions before the optimizer accumulates stable momentum estimates. LR warmup is complementary to clipping — clipping is a safety net while warmup prevents the problem from occurring."},{"type":"text","content":"Spectral normalization (Miyato 2018) constrains the spectral radius of each weight matrix to be ≤ 1 by dividing by the top singular value: W_sn = W/σ₁(W). This eliminates gradient explosion at the source. Used in GANs (discriminator stabilization) and some transformer variants as an alternative to clipping."},{"type":"heading","level":2,"content":"Strategy Comparison"},{"type":"callout","variant":"info","title":"LLM Training Standard","content":"All major LLM training recipes (GPT-3, LLaMA, Mistral) use global norm clipping with max_norm=1.0, applied after gradient accumulation and before optimizer.step(). Log the pre-clip norm to W\u0026B every step — sustained norms above 5× the clip threshold indicate architecture or LR issues that clipping alone cannot fix."},{"type":"table","headers":["Strategy","Direction preserved","LLM standard","When to use"],"rows":[["Value clipping (clip_grad_value_)","No — distorted","No","Simple RNNs, legacy code"],["Norm clipping (clip_grad_norm_)","Yes — only scale changes","Yes (max_norm=1.0)","Default for all modern deep networks"],["Adaptive per-layer norm clipping","Yes","Rare","Heterogeneous architectures"],["Spectral normalization","N/A — prevents explosion","No","GANs, when stability is critical"],["No clipping","N/A","No","Only when spectral norm guarantees bounded gradients"]]},{"type":"list","ordered":false,"items":["Log grad_norm before clipping every step — sudden spikes are early warning of instability.","LR warmup complements clipping: small initial LR reduces early gradient explosion risk.","If \u003e30% of steps are clipped, reduce learning rate — clipping is a safety net, not a substitute for LR tuning.","With gradient accumulation, clip once after all micro-steps, not per micro-step.","Spectral normalization on weight matrices bounds ρ(W) ≤ 1, eliminating explosion at the source."]},{"type":"divider"}]"
---
# Exploding Gradients — Clipping Strategies

Exploding gradients are the opposite of vanishing: when the spectral radius of each Jacobian exceeds 1, the product of Jacobians grows exponentially with depth or sequence length. RNNs are especially vulnerable because the same weight matrix W is multiplied at every time step — the effective depth equals the sequence length, which can be hundreds or thousands. Symptoms include NaN loss, diverging training curves, and sudden gradient norm spikes.

Two main clipping strategies exist: value clipping (per-element) and norm clipping (global scale). Norm clipping is the standard for large language models. Exploding gradients are distinct from vanishing — both can coexist in the same network when early layers vanish and late layers explode, a common pathology in very deep networks without residual connections.

## Mathematical Cause — RNN Gradient Explosion

In an RNN, hₜ = tanh(Whₜ₋₁ + Uxₜ). By the chain rule, ∂hₜ/∂h₀ = Πₖ₌₁ᵗ diag(tanh'(·)) · W. If ρ(W) > 1, then ‖∂hₜ/∂h₀‖ grows as ρ(W)ᵀ. For ρ(W) = 1.1 and T=100, gradient magnitude reaches 1.1¹⁰⁰ ≈ 13,780. Even modest spectral radii above 1 produce catastrophic explosion over long sequences.

```python
import torch
import torch.nn as nn

def simulate_explosion(seq_len=50, hidden=32, spectral_radius=1.1, seed=0):
    torch.manual_seed(seed)
    rnn = nn.RNNCell(hidden, hidden, nonlinearity='tanh')
    with torch.no_grad():
        U, S, V = torch.linalg.svd(rnn.weight_hh)
        rnn.weight_hh.data = (U * (S * spectral_radius / S[0]).unsqueeze(0)) @ V
    h = torch.zeros(1, hidden, requires_grad=True)
    h_curr = h
    for t in range(seq_len):
        h_curr = rnn(torch.randn(1, hidden), h_curr)
    h_curr.mean().backward()
    print(f'rho={spectral_radius}, T={seq_len}: grad norm={h.grad.norm():.3e}, expected~{spectral_radius**seq_len:.3e}')

simulate_explosion(seq_len=30, spectral_radius=1.05)
simulate_explosion(seq_len=30, spectral_radius=1.20)
```

## Value Clipping vs Norm Clipping

Value clipping clips each gradient element independently: gᵢ ← clip(gᵢ, −c, c). This changes the gradient direction — relative magnitudes across parameters are altered. Norm clipping rescales the entire gradient: if ‖g‖ > c, then g ← g · c/‖g‖. This preserves direction while bounding magnitude. Norm clipping is the standard in LLM training — GPT, T5, LLaMA all use max_norm=1.0.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def compare_clipping(clip_val=1.0):
    torch.manual_seed(7)
    model = nn.Linear(10, 10)
    (model(torch.randn(4, 10)) * 100).mean().backward()
    g_orig = model.weight.grad.clone()
    orig_dir = F.normalize(g_orig.flatten(), dim=0)

    model.weight.grad.data = g_orig.clone()
    torch.nn.utils.clip_grad_value_(model.parameters(), clip_value=clip_val)
    cos_value = (orig_dir * F.normalize(model.weight.grad.flatten(), dim=0)).sum().item()

    model.weight.grad.data = g_orig.clone()
    torch.nn.utils.clip_grad_norm_(model.parameters(), max_norm=clip_val)
    cos_norm  = (orig_dir * F.normalize(model.weight.grad.flatten(), dim=0)).sum().item()

    print(f'Original norm: {g_orig.norm():.4f}')
    print(f'Value clip cosine sim: {cos_value:.6f}')
    print(f'Norm  clip cosine sim: {cos_norm:.6f}')
    print('Norm clipping preserves direction (cos≈1); value clipping distorts it.')

compare_clipping()
```

## Gradient Norm Monitoring During Training

Logging the pre-clip gradient norm every step is the primary health metric for deep network training. A healthy norm stays in a stable range; spikes indicate instability. If more than 30% of steps require clipping, the learning rate is too high. If gradient norms are consistently near zero in early layers, vanishing is the issue — clipping cannot fix vanishing gradients.

```python
import torch
import torch.nn as nn
import numpy as np

def train_with_grad_monitoring(n_steps=200, clip=1.0, seed=0):
    torch.manual_seed(seed)
    model = nn.Sequential(
        nn.Linear(64, 256), nn.Tanh(),
        nn.Linear(256, 256), nn.Tanh(),
        nn.Linear(256, 10)
    )
    optimizer = torch.optim.Adam(model.parameters(), lr=1e-3)
    grad_norms, clipped = [], 0
    for step in range(n_steps):
        x, y = torch.randn(32, 64), torch.randint(0, 10, (32,))
        nn.CrossEntropyLoss()(model(x), y).backward()
        total_norm = torch.nn.utils.clip_grad_norm_(model.parameters(), max_norm=clip)
        grad_norms.append(total_norm.item())
        if total_norm.item() > clip: clipped += 1
        optimizer.step(); optimizer.zero_grad()
    print(f'Clip={clip}: {clipped}/{n_steps} steps clipped ({100*clipped/n_steps:.1f}%)')
    print(f'Grad norm: mean={np.mean(grad_norms):.4f} max={np.max(grad_norms):.4f}')

train_with_grad_monitoring(clip=1.0)
```

## Gradient Accumulation with Correct Clipping

Gradient accumulation simulates a larger effective batch size by accumulating gradients over multiple micro-steps before calling optimizer.step(). The critical rule: clip after all micro-steps, never before. Clipping each micro-batch independently applies multiple clipping operations and the final gradient does not correspond to a single clipped global gradient. Scale the loss by 1/accum_steps before backward to normalize the accumulated gradient.

```python
import torch
import torch.nn as nn

def train_with_accumulation(accum_steps=4, clip=1.0, n_iters=50):
    torch.manual_seed(0)
    model = nn.Sequential(nn.Linear(32, 64), nn.ReLU(), nn.Linear(64, 4))
    optimizer = torch.optim.AdamW(model.parameters(), lr=1e-3)
    criterion = nn.CrossEntropyLoss()
    for step in range(n_iters):
        optimizer.zero_grad()
        total_loss = 0.0
        for _ in range(accum_steps):
            x = torch.randn(8, 32)
            y = torch.randint(0, 4, (8,))
            loss = criterion(model(x), y) / accum_steps
            loss.backward()
            total_loss += loss.item()
        grad_norm = torch.nn.utils.clip_grad_norm_(model.parameters(), max_norm=clip)
        optimizer.step()
        if step % 10 == 0:
            print(f'Step {step:3d}: loss={total_loss:.4f} grad_norm={grad_norm:.4f}')

train_with_accumulation()
```

## LR Warmup and Spectral Normalization

Learning rate warmup linearly increases LR from 0 to the target over the first few hundred steps. At the start of training, parameters are randomly initialized and gradients can be large and inconsistent. A small initial LR prevents early gradient explosions before the optimizer accumulates stable momentum estimates. LR warmup is complementary to clipping — clipping is a safety net while warmup prevents the problem from occurring.

Spectral normalization (Miyato 2018) constrains the spectral radius of each weight matrix to be ≤ 1 by dividing by the top singular value: W_sn = W/σ₁(W). This eliminates gradient explosion at the source. Used in GANs (discriminator stabilization) and some transformer variants as an alternative to clipping.

## Strategy Comparison

> **LLM Training Standard**: All major LLM training recipes (GPT-3, LLaMA, Mistral) use global norm clipping with max_norm=1.0, applied after gradient accumulation and before optimizer.step(). Log the pre-clip norm to W&B every step — sustained norms above 5× the clip threshold indicate architecture or LR issues that clipping alone cannot fix.

| Strategy | Direction preserved | LLM standard | When to use |
| --- | --- | --- | --- |
| Value clipping (clip_grad_value_) | No — distorted | No | Simple RNNs, legacy code |
| Norm clipping (clip_grad_norm_) | Yes — only scale changes | Yes (max_norm=1.0) | Default for all modern deep networks |
| Adaptive per-layer norm clipping | Yes | Rare | Heterogeneous architectures |
| Spectral normalization | N/A — prevents explosion | No | GANs, when stability is critical |
| No clipping | N/A | No | Only when spectral norm guarantees bounded gradients |

- Log grad_norm before clipping every step — sudden spikes are early warning of instability.
- LR warmup complements clipping: small initial LR reduces early gradient explosion risk.
- If >30% of steps are clipped, reduce learning rate — clipping is a safety net, not a substitute for LR tuning.
- With gradient accumulation, clip once after all micro-steps, not per micro-step.
- Spectral normalization on weight matrices bounds ρ(W) ≤ 1, eliminating explosion at the source.

---

