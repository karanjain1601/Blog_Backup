---
title: "Adam — Adaptive Learning Rates and Bias Correction"
slug: "adam-optimizer"
description: "Rigorous derivation of Adam combining RMSProp and momentum, bias correction analysis, convergence issues in convex case, AMSGrad fix, and practical guidance on hyperparameter selection."
tags: ["optimization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Adam (Adaptive Moment Estimation) combines momentum with RMSProp: it maintains both a first moment (exponential moving average of gradients) and a second moment (EMA of squared gradients). This gives each parameter its own adaptive learning rate, inversely proportional to the square root of its gradient variance. Adaptive rates are especially valuable for NLP: embedding tables receive sparse updates — most embeddings are untouched in any given batch. Adam amplifies LR for rarely-updated parameters and dampens it for frequently-updated ones. These properties explain why Adam dominates deep learning for language, speech, and multimodal models."}, {"type": "heading", "level": 2, "content": "Core Algorithm: First and Second Moments"}, {"type": "text", "content": "First moment: m_t = beta1*m_{t-1} + (1-beta1)*g_t. Second moment: v_t = beta2*v_{t-1} + (1-beta2)*g_t^2 (uncentered variance). Bias correction: m_hat_t = m_t/(1-beta1^t), v_hat_t = v_t/(1-beta2^t). Update: theta_t = theta_{t-1} - alpha * m_hat_t / (sqrt(v_hat_t) + eps). Bias correction is critical: moments initialized at zero, so early estimates are biased toward zero — without correction, effective LR is far smaller than alpha in the first hundreds of steps. Defaults: beta1=0.9, beta2=0.999, eps=1e-8, alpha=1e-3. The second moment warms up more slowly than the first: with beta2=0.999, it takes ~1000 steps to be reliable."}, {"type": "code", "language": "python", "content": "import numpy as np\n\ndef adam_step(g, m, v, t, lr=1e-3, b1=0.9, b2=0.999, eps=1e-8):\n    m = b1 * m + (1 - b1) * g\n    v = b2 * v + (1 - b2) * g ** 2\n    # bias-corrected estimates\n    m_hat = m / (1 - b1 ** t)\n    v_hat = v / (1 - b2 ** t)\n    update = lr * m_hat / (np.sqrt(v_hat) + eps)\n    return update, m, v\n\ndef adam_no_correction(g, m, v, lr=1e-3, b1=0.9, b2=0.999, eps=1e-8):\n    m = b1 * m + (1 - b1) * g\n    v = b2 * v + (1 - b2) * g ** 2\n    return lr * m / (np.sqrt(v) + eps), m, v\n\n# Show bias effect at early steps (true gradient = 1.0)\ng = np.array([1.0])\nm = v = np.zeros(1)\nprint(\"step | corrected_update | uncorrected_update\")\nfor t in range(1, 6):\n    u_corr, m, v = adam_step(g, m, v, t)\n    m2 = v2 = np.zeros(1)\n    for tt in range(1, t + 1):\n        u_unc, m2, v2 = adam_no_correction(g, m2, v2)\n    print(f\"  {t}  |    {u_corr[0]:.6f}    |    {u_unc[0]:.6f}\")\n"}, {"type": "heading", "level": 2, "content": "Why Adaptive Rates Help: Sparse Gradients"}, {"type": "text", "content": "For NLP tasks with embedding tables: most embeddings are not activated in any given batch, producing sparse gradients. Vanilla SGD applies the same LR to all parameters regardless of update frequency. Adam's 1/sqrt(v_hat) scales down LR for frequently-updated parameters (large v_hat_t near E[g^2]) and scales up for rarely-updated parameters (small v_hat_t). This is why Adam is standard for NLP while SGD is competitive for vision. The epsilon value matters: prevents division by zero for zero-gradient parameters, but eps too large (e.g., 1e-3) makes the denominator dominated by eps, causing Adam to behave nearly like SGD with uniform step sizes — defeating the adaptive purpose."}, {"type": "code", "language": "python", "content": "import numpy as np\n\nnp.random.seed(42)\n# Sparse gradient problem: 1000 params, only 5 active per step\nn_params = 1000\nn_active = 5\nn_steps = 500\nlr = 1e-2\n\n# Ground truth: all params = 1.0\ntheta_adam = np.zeros(n_params)\ntheta_sgd  = np.zeros(n_params)\nm = np.zeros(n_params)\nv = np.zeros(n_params)\n\nlosses_adam, losses_sgd = [], []\nfor t in range(1, n_steps + 1):\n    # sparse gradient: random subset activated\n    idx = np.random.choice(n_params, n_active, replace=False)\n    g = np.zeros(n_params)\n    g[idx] = theta_adam[idx] - 1.0  # gradient of (theta-1)^2\n\n    m = 0.9 * m + 0.1 * g\n    v = 0.999 * v + 0.001 * g ** 2\n    m_hat = m / (1 - 0.9 ** t)\n    v_hat = v / (1 - 0.999 ** t)\n    theta_adam -= lr * m_hat / (np.sqrt(v_hat) + 1e-8)\n\n    g_sgd = np.zeros(n_params)\n    g_sgd[idx] = theta_sgd[idx] - 1.0\n    theta_sgd -= lr * g_sgd\n\n    losses_adam.append(np.mean((theta_adam - 1) ** 2))\n    losses_sgd.append(np.mean((theta_sgd - 1) ** 2))\n\nprint(f\"Final MSE — Adam: {losses_adam[-1]:.6f}, SGD: {losses_sgd[-1]:.6f}\")\nprint(f\"Adam converges faster on sparse problems by {losses_sgd[-1]/losses_adam[-1]:.1f}x\")\n"}, {"type": "heading", "level": 2, "content": "Bias Correction Analysis"}, {"type": "text", "content": "Without bias correction at t=1: m_1 = (1-beta1)*g_1, i.e., only 10% of gradient magnitude for beta1=0.9. The update would be wildly underscaled in early steps. Bias correction recovers the true estimate: m_hat_1 = m_1/(1-beta1^1) = g_1. At t=10: 1-beta1^10 ~ 0.651, so correction is still significant (~35% underestimate without it). At t=100: correction is negligible. The second moment is much slower to warm up: beta2=0.999 means 1-beta2^100 = 0.095, so v_hat is only 9.5% accurate after 100 steps — making the effective LR much larger than intended. This motivates LR warmup: delaying the full LR until v_hat is reliable, typically after 1000+ steps with beta2=0.999."}, {"type": "heading", "level": 2, "content": "Non-Convergence in Convex Case and AMSGrad"}, {"type": "text", "content": "Reddi et al. (2018) proved Adam can fail to converge even on simple convex problems. The counterexample: a 1D problem where the optimal solution requires accumulated knowledge from rare large gradients. Adam's decaying v_hat forgets these large gradients over time, and the effective LR grows when it should stay small. The fix: AMSGrad maintains v_hat_max = max(v_hat_max, v_hat_t) — a never-decreasing denominator — ensuring effective step size is non-increasing. This guarantees convergence. In practice, AMSGrad performs similarly to Adam on real tasks; the counterexample requires adversarially chosen sequences. Nevertheless, AMSGrad is the theoretically-safe choice and available in PyTorch via amsgrad=True."}, {"type": "code", "language": "python", "content": "import numpy as np\n\ndef amsgrad_step(g, m, v, v_max, t, lr=1e-3, b1=0.9, b2=0.999, eps=1e-8):\n    m = b1 * m + (1 - b1) * g\n    v = b2 * v + (1 - b2) * g ** 2\n    m_hat = m / (1 - b1 ** t)\n    v_hat = v / (1 - b2 ** t)\n    v_max = np.maximum(v_max, v_hat)  # never-decreasing denominator\n    update = lr * m_hat / (np.sqrt(v_max) + eps)\n    return update, m, v, v_max\n\n# Reddi-style problem: gradient alternates between large rare and small frequent\nnp.random.seed(0)\nn_steps = 2000\ntheta_adam = np.zeros(1)\ntheta_ams  = np.zeros(1)\nm_a = v_a = m_s = v_s = np.zeros(1)\nv_max = np.zeros(1)\n\nfor t in range(1, n_steps + 1):\n    # rare large gradient (every 100 steps) else small\n    g = np.array([10.0]) if t % 101 == 0 else np.array([-0.1])\n\n    m_a = 0.9 * m_a + 0.1 * g\n    v_a = 0.999 * v_a + 0.001 * g ** 2\n    m_hat = m_a / (1 - 0.9 ** t)\n    v_hat = v_a / (1 - 0.999 ** t)\n    theta_adam -= 1e-3 * m_hat / (np.sqrt(v_hat) + 1e-8)\n\n    upd, m_s, v_s, v_max = amsgrad_step(g, m_s, v_s, v_max, t)\n    theta_ams -= upd\n\nprint(f\"Adam final theta:    {theta_adam[0]:.4f}\")\nprint(f\"AMSGrad final theta: {theta_ams[0]:.4f}\")\n"}, {"type": "heading", "level": 2, "content": "ML Connections: Transformer Training"}, {"type": "text", "content": "Adam is the de facto optimizer for transformer training. Attention layers have gradient magnitudes that vary dramatically across heads and positions; embedding layers receive sparse updates. Both conditions favor adaptive rates. Typical transformer hyperparameters: beta1=0.9, beta2=0.999, eps=1e-8, LR warmup for ~4% of training, then cosine decay. GPT-3 used LR=6e-5 with batch size 3.2M tokens. The epsilon value matters more than commonly acknowledged: eps=1e-8 is standard but eps=1e-6 can improve stability for poorly-scaled losses. Some LLM training uses beta2=0.95 to reduce the effective averaging window and respond faster to gradient changes during distribution shift early in training."}, {"type": "heading", "level": 2, "content": "Implementation Pitfalls"}, {"type": "text", "content": "Pitfall 1: forgetting bias correction — training appears slow in the first 100-500 steps because the effective LR is much lower than set. Pitfall 2: epsilon too large — if eps=0.1, the denominator sqrt(v_hat)+eps approximates eps for small gradients, giving nearly uniform step sizes and defeating adaptation. Pitfall 3: weight decay in standard Adam is not equivalent to L2 regularization — use AdamW instead. Pitfall 4: implementation differences — PyTorch applies eps inside the denominator as 1/(sqrt(v_hat)+eps); some TensorFlow versions apply it differently. Always verify behavior matches expectation by checking the effective LR magnitude early in training."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Default Adam recipe: LR=1e-3 (fine-tuning: 1e-4 to 5e-5), beta1=0.9, beta2=0.999, eps=1e-8. For transformers: use AdamW (not Adam) with weight decay 0.01-0.1. Monitor the second moment v_hat_t across layers — if v_hat_t is very small for some layers, eps dominates and those layers get equal LR to others, defeating adaptive purpose. Track effective LR = alpha/sqrt(v_hat_t) per layer. For sparse NLP models, consider increasing beta2 to 0.9999 for more stable second-moment estimates, combined with longer warmup."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn as nn\n\n# Simulate transformer-like training with LR monitoring\ntorch.manual_seed(42)\nmodel = nn.Sequential(\n    nn.Linear(128, 256), nn.ReLU(),\n    nn.Linear(256, 256), nn.ReLU(),\n    nn.Linear(256, 10)\n)\noptimizer = torch.optim.Adam(model.parameters(), lr=1e-3,\n                              betas=(0.9, 0.999), eps=1e-8)\n\nx = torch.randn(32, 128)\ny = torch.randint(0, 10, (32,))\ncriterion = nn.CrossEntropyLoss()\n\nfor step in range(50):\n    optimizer.zero_grad()\n    loss = criterion(model(x), y)\n    loss.backward()\n    optimizer.step()\n\n# Inspect effective LR = lr / sqrt(v_hat) per parameter group\nprint(\"Effective LR per layer (first param tensor):\")\nfor i, pg in enumerate(optimizer.param_groups):\n    for p in pg['params']:\n        state = optimizer.state[p]\n        if len(state) > 0 and p.grad is not None:\n            exp_avg_sq = state['exp_avg_sq']\n            step_count = state['step']\n            bc = 1 - 0.999 ** step_count.item()\n            v_hat = exp_avg_sq / bc\n            eff_lr = pg['lr'] / (v_hat.sqrt() + 1e-8)\n            print(f\"  shape={tuple(p.shape)}  eff_lr mean={eff_lr.mean():.2e}  std={eff_lr.std():.2e}\")\n            break\n"}, {"type": "callout", "title": "Use AdamW Not Adam for Regularized Training", "content": "Standard Adam with weight_decay adds lambda*theta to the gradient before the adaptive update. The effective decay becomes lambda*alpha/(sqrt(v_hat)+eps) — varying per parameter. Parameters with large gradient history (large v) get weaker regularization. AdamW decouples weight decay: apply theta <- theta*(1-lambda*alpha) directly, before the adaptive gradient step. This gives uniform shrinkage regardless of gradient history. Always use AdamW for regularized training. The difference is significant for large transformer models where gradient magnitudes vary by orders of magnitude across layers."}, {"type": "table", "headers": ["Hyperparameter", "Default", "Effect of Increasing", "Effect of Decreasing"], "rows": [["alpha (learning rate)", "1e-3", "Faster but less stable", "Slower convergence"], ["beta1 (momentum)", "0.9", "More momentum, smoother updates", "Less momentum, noisier updates"], ["beta2 (second moment)", "0.999", "Slower adaptation, more stable v_hat", "Faster adaptation, noisier v_hat"], ["eps (epsilon)", "1e-8", "More uniform LR (less adaptive)", "More adaptive, potential numerical issues"], ["weight_decay", "0 (Adam) / 0.01-0.1 (AdamW)", "Stronger regularization", "Less regularization"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "items": ["Adam = momentum (first moment) + RMSProp (second moment), with bias correction for both.", "Bias correction is essential: without it, early updates are massively underscaled (10% of intended LR at t=1 with beta1=0.9).", "Adaptive rates help most for sparse gradients (NLP embeddings); for dense vision tasks, SGD is often competitive.", "Adam can fail to converge on convex problems (Reddi 2018); AMSGrad fixes this with a non-decreasing denominator.", "Use AdamW, not Adam, whenever weight decay is needed — standard Adam's L2 is corrupted by adaptive rates.", "Monitor effective LR = alpha/sqrt(v_hat) per layer; if eps dominates (v_hat << eps^2), adaptation is lost.", "Beta2=0.999 requires ~1000 steps to warm up; combine with LR warmup to avoid early instability from unreliable v_hat."]}]"
---

# Adam — Adaptive Learning Rates and Bias Correction

Adam (Adaptive Moment Estimation) combines momentum with RMSProp: it maintains both a first moment (exponential moving average of gradients) and a second moment (EMA of squared gradients). This gives each parameter its own adaptive learning rate, inversely proportional to the square root of its gradient variance. Adaptive rates are especially valuable for NLP: embedding tables receive sparse updates — most embeddings are untouched in any given batch. Adam amplifies LR for rarely-updated parameters and dampens it for frequently-updated ones. These properties explain why Adam dominates deep learning for language, speech, and multimodal models.

## Core Algorithm: First and Second Moments

First moment: m_t = beta1*m_{t-1} + (1-beta1)*g_t. Second moment: v_t = beta2*v_{t-1} + (1-beta2)*g_t^2 (uncentered variance). Bias correction: m_hat_t = m_t/(1-beta1^t), v_hat_t = v_t/(1-beta2^t). Update: theta_t = theta_{t-1} - alpha * m_hat_t / (sqrt(v_hat_t) + eps). Bias correction is critical: moments initialized at zero, so early estimates are biased toward zero — without correction, effective LR is far smaller than alpha in the first hundreds of steps. Defaults: beta1=0.9, beta2=0.999, eps=1e-8, alpha=1e-3. The second moment warms up more slowly than the first: with beta2=0.999, it takes ~1000 steps to be reliable.

```python
import numpy as np

def adam_step(g, m, v, t, lr=1e-3, b1=0.9, b2=0.999, eps=1e-8):
    m = b1 * m + (1 - b1) * g
    v = b2 * v + (1 - b2) * g ** 2
    # bias-corrected estimates
    m_hat = m / (1 - b1 ** t)
    v_hat = v / (1 - b2 ** t)
    update = lr * m_hat / (np.sqrt(v_hat) + eps)
    return update, m, v

def adam_no_correction(g, m, v, lr=1e-3, b1=0.9, b2=0.999, eps=1e-8):
    m = b1 * m + (1 - b1) * g
    v = b2 * v + (1 - b2) * g ** 2
    return lr * m / (np.sqrt(v) + eps), m, v

# Show bias effect at early steps (true gradient = 1.0)
g = np.array([1.0])
m = v = np.zeros(1)
print("step | corrected_update | uncorrected_update")
for t in range(1, 6):
    u_corr, m, v = adam_step(g, m, v, t)
    m2 = v2 = np.zeros(1)
    for tt in range(1, t + 1):
        u_unc, m2, v2 = adam_no_correction(g, m2, v2)
    print(f"  {t}  |    {u_corr[0]:.6f}    |    {u_unc[0]:.6f}")

```

## Why Adaptive Rates Help: Sparse Gradients

For NLP tasks with embedding tables: most embeddings are not activated in any given batch, producing sparse gradients. Vanilla SGD applies the same LR to all parameters regardless of update frequency. Adam's 1/sqrt(v_hat) scales down LR for frequently-updated parameters (large v_hat_t near E[g^2]) and scales up for rarely-updated parameters (small v_hat_t). This is why Adam is standard for NLP while SGD is competitive for vision. The epsilon value matters: prevents division by zero for zero-gradient parameters, but eps too large (e.g., 1e-3) makes the denominator dominated by eps, causing Adam to behave nearly like SGD with uniform step sizes — defeating the adaptive purpose.

```python
import numpy as np

np.random.seed(42)
# Sparse gradient problem: 1000 params, only 5 active per step
n_params = 1000
n_active = 5
n_steps = 500
lr = 1e-2

# Ground truth: all params = 1.0
theta_adam = np.zeros(n_params)
theta_sgd  = np.zeros(n_params)
m = np.zeros(n_params)
v = np.zeros(n_params)

losses_adam, losses_sgd = [], []
for t in range(1, n_steps + 1):
    # sparse gradient: random subset activated
    idx = np.random.choice(n_params, n_active, replace=False)
    g = np.zeros(n_params)
    g[idx] = theta_adam[idx] - 1.0  # gradient of (theta-1)^2

    m = 0.9 * m + 0.1 * g
    v = 0.999 * v + 0.001 * g ** 2
    m_hat = m / (1 - 0.9 ** t)
    v_hat = v / (1 - 0.999 ** t)
    theta_adam -= lr * m_hat / (np.sqrt(v_hat) + 1e-8)

    g_sgd = np.zeros(n_params)
    g_sgd[idx] = theta_sgd[idx] - 1.0
    theta_sgd -= lr * g_sgd

    losses_adam.append(np.mean((theta_adam - 1) ** 2))
    losses_sgd.append(np.mean((theta_sgd - 1) ** 2))

print(f"Final MSE — Adam: {losses_adam[-1]:.6f}, SGD: {losses_sgd[-1]:.6f}")
print(f"Adam converges faster on sparse problems by {losses_sgd[-1]/losses_adam[-1]:.1f}x")

```

## Bias Correction Analysis

Without bias correction at t=1: m_1 = (1-beta1)*g_1, i.e., only 10% of gradient magnitude for beta1=0.9. The update would be wildly underscaled in early steps. Bias correction recovers the true estimate: m_hat_1 = m_1/(1-beta1^1) = g_1. At t=10: 1-beta1^10 ~ 0.651, so correction is still significant (~35% underestimate without it). At t=100: correction is negligible. The second moment is much slower to warm up: beta2=0.999 means 1-beta2^100 = 0.095, so v_hat is only 9.5% accurate after 100 steps — making the effective LR much larger than intended. This motivates LR warmup: delaying the full LR until v_hat is reliable, typically after 1000+ steps with beta2=0.999.

## Non-Convergence in Convex Case and AMSGrad

Reddi et al. (2018) proved Adam can fail to converge even on simple convex problems. The counterexample: a 1D problem where the optimal solution requires accumulated knowledge from rare large gradients. Adam's decaying v_hat forgets these large gradients over time, and the effective LR grows when it should stay small. The fix: AMSGrad maintains v_hat_max = max(v_hat_max, v_hat_t) — a never-decreasing denominator — ensuring effective step size is non-increasing. This guarantees convergence. In practice, AMSGrad performs similarly to Adam on real tasks; the counterexample requires adversarially chosen sequences. Nevertheless, AMSGrad is the theoretically-safe choice and available in PyTorch via amsgrad=True.

```python
import numpy as np

def amsgrad_step(g, m, v, v_max, t, lr=1e-3, b1=0.9, b2=0.999, eps=1e-8):
    m = b1 * m + (1 - b1) * g
    v = b2 * v + (1 - b2) * g ** 2
    m_hat = m / (1 - b1 ** t)
    v_hat = v / (1 - b2 ** t)
    v_max = np.maximum(v_max, v_hat)  # never-decreasing denominator
    update = lr * m_hat / (np.sqrt(v_max) + eps)
    return update, m, v, v_max

# Reddi-style problem: gradient alternates between large rare and small frequent
np.random.seed(0)
n_steps = 2000
theta_adam = np.zeros(1)
theta_ams  = np.zeros(1)
m_a = v_a = m_s = v_s = np.zeros(1)
v_max = np.zeros(1)

for t in range(1, n_steps + 1):
    # rare large gradient (every 100 steps) else small
    g = np.array([10.0]) if t % 101 == 0 else np.array([-0.1])

    m_a = 0.9 * m_a + 0.1 * g
    v_a = 0.999 * v_a + 0.001 * g ** 2
    m_hat = m_a / (1 - 0.9 ** t)
    v_hat = v_a / (1 - 0.999 ** t)
    theta_adam -= 1e-3 * m_hat / (np.sqrt(v_hat) + 1e-8)

    upd, m_s, v_s, v_max = amsgrad_step(g, m_s, v_s, v_max, t)
    theta_ams -= upd

print(f"Adam final theta:    {theta_adam[0]:.4f}")
print(f"AMSGrad final theta: {theta_ams[0]:.4f}")

```

## ML Connections: Transformer Training

Adam is the de facto optimizer for transformer training. Attention layers have gradient magnitudes that vary dramatically across heads and positions; embedding layers receive sparse updates. Both conditions favor adaptive rates. Typical transformer hyperparameters: beta1=0.9, beta2=0.999, eps=1e-8, LR warmup for ~4% of training, then cosine decay. GPT-3 used LR=6e-5 with batch size 3.2M tokens. The epsilon value matters more than commonly acknowledged: eps=1e-8 is standard but eps=1e-6 can improve stability for poorly-scaled losses. Some LLM training uses beta2=0.95 to reduce the effective averaging window and respond faster to gradient changes during distribution shift early in training.

## Implementation Pitfalls

Pitfall 1: forgetting bias correction — training appears slow in the first 100-500 steps because the effective LR is much lower than set. Pitfall 2: epsilon too large — if eps=0.1, the denominator sqrt(v_hat)+eps approximates eps for small gradients, giving nearly uniform step sizes and defeating adaptation. Pitfall 3: weight decay in standard Adam is not equivalent to L2 regularization — use AdamW instead. Pitfall 4: implementation differences — PyTorch applies eps inside the denominator as 1/(sqrt(v_hat)+eps); some TensorFlow versions apply it differently. Always verify behavior matches expectation by checking the effective LR magnitude early in training.

## Practical Guidance

Default Adam recipe: LR=1e-3 (fine-tuning: 1e-4 to 5e-5), beta1=0.9, beta2=0.999, eps=1e-8. For transformers: use AdamW (not Adam) with weight decay 0.01-0.1. Monitor the second moment v_hat_t across layers — if v_hat_t is very small for some layers, eps dominates and those layers get equal LR to others, defeating adaptive purpose. Track effective LR = alpha/sqrt(v_hat_t) per layer. For sparse NLP models, consider increasing beta2 to 0.9999 for more stable second-moment estimates, combined with longer warmup.

```python
import torch
import torch.nn as nn

# Simulate transformer-like training with LR monitoring
torch.manual_seed(42)
model = nn.Sequential(
    nn.Linear(128, 256), nn.ReLU(),
    nn.Linear(256, 256), nn.ReLU(),
    nn.Linear(256, 10)
)
optimizer = torch.optim.Adam(model.parameters(), lr=1e-3,
                              betas=(0.9, 0.999), eps=1e-8)

x = torch.randn(32, 128)
y = torch.randint(0, 10, (32,))
criterion = nn.CrossEntropyLoss()

for step in range(50):
    optimizer.zero_grad()
    loss = criterion(model(x), y)
    loss.backward()
    optimizer.step()

# Inspect effective LR = lr / sqrt(v_hat) per parameter group
print("Effective LR per layer (first param tensor):")
for i, pg in enumerate(optimizer.param_groups):
    for p in pg['params']:
        state = optimizer.state[p]
        if len(state) > 0 and p.grad is not None:
            exp_avg_sq = state['exp_avg_sq']
            step_count = state['step']
            bc = 1 - 0.999 ** step_count.item()
            v_hat = exp_avg_sq / bc
            eff_lr = pg['lr'] / (v_hat.sqrt() + 1e-8)
            print(f"  shape={tuple(p.shape)}  eff_lr mean={eff_lr.mean():.2e}  std={eff_lr.std():.2e}")
            break

```

> **Use AdamW Not Adam for Regularized Training**: Standard Adam with weight_decay adds lambda*theta to the gradient before the adaptive update. The effective decay becomes lambda*alpha/(sqrt(v_hat)+eps) — varying per parameter. Parameters with large gradient history (large v) get weaker regularization. AdamW decouples weight decay: apply theta <- theta*(1-lambda*alpha) directly, before the adaptive gradient step. This gives uniform shrinkage regardless of gradient history. Always use AdamW for regularized training. The difference is significant for large transformer models where gradient magnitudes vary by orders of magnitude across layers.

| Hyperparameter | Default | Effect of Increasing | Effect of Decreasing |
|---|---|---|---|
| alpha (learning rate) | 1e-3 | Faster but less stable | Slower convergence |
| beta1 (momentum) | 0.9 | More momentum, smoother updates | Less momentum, noisier updates |
| beta2 (second moment) | 0.999 | Slower adaptation, more stable v_hat | Faster adaptation, noisier v_hat |
| eps (epsilon) | 1e-8 | More uniform LR (less adaptive) | More adaptive, potential numerical issues |
| weight_decay | 0 (Adam) / 0.01-0.1 (AdamW) | Stronger regularization | Less regularization |

---

## Key Takeaways

- Adam = momentum (first moment) + RMSProp (second moment), with bias correction for both.
- Bias correction is essential: without it, early updates are massively underscaled (10% of intended LR at t=1 with beta1=0.9).
- Adaptive rates help most for sparse gradients (NLP embeddings); for dense vision tasks, SGD is often competitive.
- Adam can fail to converge on convex problems (Reddi 2018); AMSGrad fixes this with a non-decreasing denominator.
- Use AdamW, not Adam, whenever weight decay is needed — standard Adam's L2 is corrupted by adaptive rates.
- Monitor effective LR = alpha/sqrt(v_hat) per layer; if eps dominates (v_hat << eps^2), adaptation is lost.
- Beta2=0.999 requires ~1000 steps to warm up; combine with LR warmup to avoid early instability from unreliable v_hat.

