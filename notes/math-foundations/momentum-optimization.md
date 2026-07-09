---
title: "Momentum and Exponential Moving Averages"
slug: "momentum-optimization"
description: "Deep dive into heavy ball momentum, exponential moving averages as low-pass filters, accelerated convergence on convex problems, EMA target networks in RL, and stochastic weight averaging for improved generalization."
tags: ["optimization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Momentum is the single most impactful modification to basic gradient descent, providing O(1/T²) convergence for convex smooth functions vs O(1/T) for vanilla GD. But momentum is more than an acceleration technique — its underlying mechanism (exponential moving average of gradients) is the core primitive in Adam's first moment, EMA target networks in deep RL (DQN, BYOL), model weight averaging (SWA, EMA ensembles), and temporal difference bootstrapping. Understanding momentum through the lens of exponential moving averages, effective step size, oscillation damping, and the physical ball-on-slope analogy unifies these seemingly disparate applications under a single mathematical framework applicable across optimization, reinforcement learning, and generative modeling."}, {"type": "heading", "level": 2, "content": "Core Definition: Heavy Ball Method"}, {"type": "text", "content": "The heavy ball momentum update (Polyak 1964): vₜ = βvₜ₋₁ + ηgₜ; θₜ = θₜ₋₁ − vₜ, where gₜ = ∇L(θₜ₋₁), β ∈ [0,1) is the momentum coefficient, η is the learning rate, and vₜ is the velocity vector. Equivalently: θₜ = θₜ₋₁ − ηgₜ − β(θₜ₋₁ − θₜ₋₂). Geometric series interpretation: vₜ = ηΣₖ₌₀^∞ βᵏ gₜ₋ₖ — velocity is an exponentially decaying weighted average of all past gradients. In consistent gradient directions, gradients reinforce: vₜ → η/(1−β) · g (steady-state velocity). In oscillating directions, they cancel: momentum damps oscillations across the valley. Effective step size in a consistent direction: η/(1−β). For β=0.9 this is 10× amplification; for β=0.99 it gives 100× amplification."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport matplotlib.pyplot as plt\n\ndef sgd_momentum(grad_f, theta0, lr, beta, n_steps, f=None):\n    \"\"\"\n    SGD with heavy ball momentum.\n    vt = beta * v_{t-1} + lr * grad(theta_{t-1})\n    theta_t = theta_{t-1} - vt\n    \"\"\"\n    theta = np.array(theta0, dtype=np.float64)\n    v = np.zeros_like(theta)\n    history = {'theta': [theta.copy()], 'loss': [f(theta)] if f else []}\n\n    for t in range(n_steps):\n        g = grad_f(theta)\n        v = beta * v + lr * g       # velocity accumulates\n        theta = theta - v\n        history['theta'].append(theta.copy())\n        if f: history['loss'].append(f(theta))\n\n    return history\n\n# Compare vanilla GD vs momentum on ill-conditioned quadratic\n# f(x,y) = 0.5*(x^2 + 100*y^2)  -- condition number kappa=100\nf = lambda x: 0.5 * (x[0]**2 + 100*x[1]**2)\ngrad_f = lambda x: np.array([x[0], 100*x[1]])\nx0 = np.array([10.0, 1.0])\n\nL, mu = 100.0, 1.0\neta_gd = 2/(mu + L)       # optimal for GD\neta_mom = 2/(np.sqrt(mu) + np.sqrt(L))**2  # optimal for momentum\nbeta_mom = ((np.sqrt(L) - np.sqrt(mu))/(np.sqrt(L) + np.sqrt(mu)))**2\n\nhist_gd = sgd_momentum(grad_f, x0, lr=eta_gd, beta=0, n_steps=300, f=f)\nhist_mom = sgd_momentum(grad_f, x0, lr=eta_mom, beta=beta_mom, n_steps=300, f=f)\n\n# Find steps to reach 1e-4 precision\nsteps_gd = next((i for i, l in enumerate(hist_gd['loss']) if l < 1e-4), 300)\nsteps_mom = next((i for i, l in enumerate(hist_mom['loss']) if l < 1e-4), 300)\nprint(f\"GD:       {steps_gd} steps to 1e-4  (kappa={L/mu:.0f})\")\nprint(f\"Momentum: {steps_mom} steps to 1e-4  (speedup: {steps_gd/max(steps_mom,1):.1f}x)\")\nprint(f\"Effective momentum step size: eta/(1-beta) = {eta_mom/(1-beta_mom):.4f}\")\nprint(f\"Momentum coefficient beta = {beta_mom:.4f}\")"}, {"type": "heading", "level": 2, "content": "Exponential Moving Average as Low-Pass Filter"}, {"type": "text", "content": "The EMA mₜ = βmₜ₋₁ + (1−β)xₜ is a recursive formula with explicit solution mₜ = (1−β)Σₖ₌₀^t βᵏ x_{t-k}. The weights (1−β)βᵏ sum to 1 (geometric series) and decay exponentially — recent values dominate. Effective window: τ = 1/(1−β). For β=0.9: window≈10 steps; β=0.99: window≈100 steps; β=0.999: window≈1000 steps. In frequency domain: EMA is a first-order IIR low-pass filter, passing low-frequency (slow trend) signals and attenuating high-frequency (noise) signals. The cutoff frequency is approximately (1−β)/(2π). Heavy ball momentum uses EMA of gradients: β=0.9 smooths gradient noise while preserving the trend direction, enabling larger effective step sizes than vanilla GD without the instability that would arise from simply using a larger learning rate directly."}, {"type": "code", "language": "python", "content": "import numpy as np\n\ndef ema(values, beta=0.9, bias_correct=True):\n    \"\"\"\n    Exponential moving average.\n    m_t = beta * m_{t-1} + (1 - beta) * x_t\n    With bias correction: m_hat_t = m_t / (1 - beta^t)\n    \"\"\"\n    m = 0.0\n    emas = []\n    for t, x in enumerate(values, start=1):\n        m = beta * m + (1 - beta) * x\n        if bias_correct:\n            m_hat = m / (1 - beta**t)\n        else:\n            m_hat = m\n        emas.append(m_hat)\n    return emas\n\n# Demonstrate effective window size\nbeta = 0.9\neffective_window = 1 / (1 - beta)\nprint(f\"beta={beta}: effective window approx {effective_window:.0f} steps\")\n\n# Show EMA tracking a step function\nn = 200\nsignal = np.concatenate([np.zeros(100), np.ones(100)])  # step at t=100\nema_90 = ema(signal, beta=0.9)\nema_99 = ema(signal, beta=0.99)\n\n# Find tracking lag: steps to reach 63% of step value after the step\nlag_90 = next((t for t, v in enumerate(ema_90[100:]) if v > 0.63), None) + 1\nlag_99 = next((t for t, v in enumerate(ema_99[100:]) if v > 0.63), None) + 1\nprint(f\"beta=0.9:  lag to 63% of step = {lag_90} steps  (approx 1/(1-beta)={1/(1-0.9):.0f})\")\nprint(f\"beta=0.99: lag to 63% of step = {lag_99} steps  (approx 1/(1-beta)={1/(1-0.99):.0f})\")\n\n# Bias correction importance for early steps\nearly_ema_no_bc = ema([1.0]*20, beta=0.9, bias_correct=False)\nearly_ema_bc = ema([1.0]*20, beta=0.9, bias_correct=True)\nprint(f\"\\nAfter 1 step with constant input=1: no-BC={early_ema_no_bc[0]:.3f} vs BC={early_ema_bc[0]:.3f}\")\nprint(f\"After 10 steps: no-BC={early_ema_no_bc[9]:.3f} vs BC={early_ema_bc[9]:.3f}\")"}, {"type": "heading", "level": 2, "content": "Accelerated Convergence: Momentum Achieves O(1/T²)"}, {"type": "text", "content": "Nesterov's acceleration theorem: for L-smooth convex f, GD with momentum achieves f(θₜ)−f* ≤ O(L‖θ₀−θ*‖²/T²), compared to O(L‖θ₀−θ*‖²/T) for vanilla GD — a factor of T speedup. For strongly convex functions: momentum achieves O(exp(−T√(μ/L))) convergence vs O(exp(−T·μ/L)) for GD — linear rate but with √κ instead of κ dependence. Optimal momentum coefficient for convex smooth problems: β = (√κ−1)/(√κ+1) where κ = L/μ. Physical intuition: the ball picks up speed downhill (momentum accumulates) and uses inertia to cross small barriers and maintain forward progress. The deceleration near the minimum prevents overshoot: near θ*, the gradient reverses direction, applying a braking force that opposes the accumulated momentum and allows the optimizer to settle."}, {"type": "heading", "level": 2, "content": "ML Connections: EMA in Deep Learning"}, {"type": "text", "content": "EMA appears in multiple critical ML components beyond optimization: (1) Adam's first moment: mₜ = β₁mₜ₋₁ + (1−β₁)gₜ (EMA of gradients with β₁=0.9). (2) DQN target network: θ⁻ = β·θ⁻ + (1−β)·θ — slow-moving copy of Q-network for stable Bellman targets (Mnih 2015). (3) BYOL (Grill 2020): online encoder θ updated by gradient; target encoder ξ = τ·ξ + (1−τ)·θ (momentum encoder), enabling self-supervised learning without negative samples. (4) Stochastic Weight Averaging (SWA, Izmailov 2018): θ_SWA = (1/n)Σθₜ (uniform average of SGD iterates), converges to flat minima and improves generalization. (5) EMA ensembles in diffusion models: a slow-moving copy of model weights is used for inference, yielding better sample quality than the current training checkpoint due to reduced noise sensitivity."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn as nn\nimport copy\n\nclass EMAModel:\n    \"\"\"\n    Exponential Moving Average of model weights.\n    Used in: BYOL target network, diffusion model inference, SWA.\n    \"\"\"\n    def __init__(self, model, decay=0.999):\n        self.decay = decay\n        self.shadow = copy.deepcopy(model)\n        # Freeze shadow -- gradients not needed\n        for p in self.shadow.parameters():\n            p.requires_grad_(False)\n\n    @torch.no_grad()\n    def update(self, model):\n        \"\"\"Update shadow weights: theta_ema = decay * theta_ema + (1-decay) * theta\"\"\"\n        for ema_param, param in zip(self.shadow.parameters(), model.parameters()):\n            ema_param.data.mul_(self.decay).add_(param.data, alpha=1.0 - self.decay)\n\n    def get_model(self):\n        return self.shadow\n\n# Demonstrate EMA model tracking\nclass TinyNet(nn.Module):\n    def __init__(self):\n        super().__init__()\n        self.fc = nn.Linear(4, 2)\n    def forward(self, x):\n        return self.fc(x)\n\nmodel = TinyNet()\nema_model = EMAModel(model, decay=0.999)\n\n# Simulate training: model weights change, EMA tracks slowly\noptimizer = torch.optim.SGD(model.parameters(), lr=0.1)\nx = torch.randn(16, 4)\ny = torch.randint(0, 2, (16,))\n\nfor step in range(100):\n    optimizer.zero_grad()\n    loss = nn.CrossEntropyLoss()(model(x), y)\n    loss.backward()\n    optimizer.step()\n    ema_model.update(model)\n\n# Check: EMA weights are smoothed version of current weights\nparam = list(model.parameters())[0].data[0, 0].item()\nema_param = list(ema_model.get_model().parameters())[0].data[0, 0].item()\nprint(f\"Current weight[0,0]: {param:.4f}\")\nprint(f\"EMA weight[0,0]:     {ema_param:.4f}\")\nprint(f\"Difference: {abs(param - ema_param):.4f} (EMA lags behind)\")\nprint(f\"Effective window: {1/(1-0.999):.0f} steps\")"}, {"type": "heading", "level": 2, "content": "Stochastic Weight Averaging (SWA)"}, {"type": "text", "content": "SWA (Izmailov 2018) averages the weights of SGD iterates sampled periodically: θ_SWA = (1/n)Σθₜ. Key insight: the average of multiple points on a loss landscape valley typically lies at a flatter point than any individual iterate. SWA with a cyclical LR schedule works as follows: train with a high LR for k steps (explores the loss basin broadly), then step to low LR (sharp descent to a local minimum), take a weight snapshot; repeat. Average all snapshots at the end. Result: the final averaged parameters converge to a broad flat minimum with better test accuracy than using any single checkpoint. Implementation uses torch.optim.swa_utils.AveragedModel for weight tracking and update_bn(loader, swa_model) to recalculate batch normalization running statistics for the averaged weights — BN affine parameters are averaged but running statistics must be recomputed from data."}, {"type": "heading", "level": 2, "content": "Implementation Pitfalls"}, {"type": "text", "content": "Momentum too high (β→1): the velocity term dominates and the optimizer overshoots, causing oscillations and eventual divergence. For convex problems, optimal β = (√κ−1)/(√κ+1). For neural networks, β=0.9 is standard; β=0.99 is used in some Adam variants. Setting β=0 recovers vanilla SGD. EMA decay too high: if decay=0.9999, the EMA lags 10,000 steps behind the current model — it tracks model changes too slowly during early training. Use lower decay (0.999) during early training and increase it toward 0.9999 during later training stages. SWA pitfall: if BN running statistics are not recalculated after weight averaging, the model produces incorrect normalizations because the averaged weights produce a different activation distribution than any individual checkpoint. Always call torch.optim.swa_utils.update_bn(loader, swa_model) after SWA averaging and before evaluation."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Use β=0.9 as the default momentum coefficient for SGD with momentum — this is the standard setting for image classification (ResNet/ImageNet training). For Adam, β₁=0.9 and β₂=0.999 are standard defaults that rarely need tuning. Use SWA when training budget is fixed and you want 1-2% accuracy improvement for free: use AveragedModel from torch.optim.swa_utils and activate SWA for the final 20-25% of training epochs. For EMA target networks in RL and contrastive learning, start with decay=0.996 (used in BYOL) or 0.99 (used in DQN) — higher decay gives more stable targets but slower tracking of the current model. Monitor the ratio ‖v‖/‖θ‖ (velocity magnitude relative to parameter magnitude) to check momentum aggressiveness: if this ratio exceeds 1, momentum is too aggressive for the current LR combination."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn as nn\nfrom torch.optim.swa_utils import AveragedModel, SWALR\n\ndef train_with_swa(model, train_loader, n_epochs=50, swa_start=40):\n    \"\"\"\n    SWA training: regular SGD for first swa_start epochs,\n    then switch to SWA mode with cyclical LR.\n    \"\"\"\n    optimizer = torch.optim.SGD(model.parameters(), lr=0.1, momentum=0.9)\n    swa_model = AveragedModel(model)\n    swa_scheduler = SWALR(optimizer, swa_lr=0.05)\n    criterion = nn.CrossEntropyLoss()\n\n    for epoch in range(n_epochs):\n        model.train()\n        for X, y in train_loader:\n            optimizer.zero_grad()\n            loss = criterion(model(X), y)\n            loss.backward()\n            optimizer.step()\n\n        if epoch >= swa_start:\n            # SWA phase: average weights across epochs\n            swa_model.update_parameters(model)\n            swa_scheduler.step()\n        else:\n            # Warmup/cosine phase\n            pass\n\n    # CRITICAL: recalculate BN statistics for averaged model\n    # (BN running stats are not averaged, only affine params)\n    # torch.optim.swa_utils.update_bn(train_loader, swa_model)\n\n    print(f\"SWA training complete. Use swa_model for inference.\")\n    print(\"Remember: call update_bn(train_loader, swa_model) before evaluation!\")\n    return swa_model\n\nprint(\"SWA training function defined.\")\nprint(\"Key insight: SWA averages weights of SGD snapshots -> flat minima -> better generalization.\")"}, {"type": "callout", "title": "Momentum Amplifies Bad Gradients Too", "content": "Momentum accumulates all past gradients — including incorrect ones at the start of training or after a sudden LR change. If the initial LR is too large (causing a bad first step), momentum will amplify that bad direction for the next 1/(1-beta) steps. Always warm up the learning rate for the first 5-10% of training. When resuming from a checkpoint, consider zeroing the momentum buffer (optimizer.state = {}) to avoid carrying over stale velocities that do not apply to the new LR schedule."}, {"type": "table", "headers": ["Method", "Convergence Rate (convex)", "Convergence Rate (strongly convex)", "Effective Step"], "rows": [["Vanilla GD", "O(1/T)", "O(exp(-mu*T/L))", "eta"], ["Heavy Ball (momentum)", "O(1/T^2) (quadratic)", "O(exp(-T*sqrt(mu/L)))", "eta/(1-beta)"], ["Nesterov (lookahead)", "O(1/T^2) (general)", "O(exp(-T*sqrt(mu/L)))", "eta/(1-beta)"], ["SWA (iterate avg)", "O(1/T)", "O(1/T) (convex rate)", "N/A"], ["EMA (exponential avg)", "Biased estimator", "Bias-variance tradeoff", "N/A"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "items": ["Heavy ball momentum vt = beta*v_{t-1} + eta*gt, theta_t = theta_{t-1} - vt amplifies consistent gradients by factor 1/(1-beta) and damps oscillating gradients.", "EMA mt = beta*m_{t-1} + (1-beta)*xt has effective window 1/(1-beta). Bias correction m_hat_t = mt/(1-beta^t) is essential for early timesteps.", "Momentum achieves O(1/T^2) convergence for convex smooth functions vs O(1/T) for GD — equivalent to sqrt(kappa) speedup for strongly convex problems.", "EMA appears in Adam (first moment), DQN target networks, BYOL contrastive learning, SWA, and diffusion model inference — a universal smoothing primitive.", "SWA averages SGD iterates sampled with cyclical LR, converging to flat minima with better generalization than any single checkpoint.", "For EMA models, always recalculate BN running statistics after weight averaging — they are not averaged, only affine parameters (gamma, beta) are.", "When resuming training after a checkpoint, consider zeroing the momentum buffer to avoid stale velocity contaminating the new LR regime."]}]"
---

# Momentum and Exponential Moving Averages

Momentum is the single most impactful modification to basic gradient descent, providing O(1/T²) convergence for convex smooth functions vs O(1/T) for vanilla GD. But momentum is more than an acceleration technique — its underlying mechanism (exponential moving average of gradients) is the core primitive in Adam's first moment, EMA target networks in deep RL (DQN, BYOL), model weight averaging (SWA, EMA ensembles), and temporal difference bootstrapping. Understanding momentum through the lens of exponential moving averages, effective step size, oscillation damping, and the physical ball-on-slope analogy unifies these seemingly disparate applications under a single mathematical framework applicable across optimization, reinforcement learning, and generative modeling.

## Core Definition: Heavy Ball Method

The heavy ball momentum update (Polyak 1964): vₜ = βvₜ₋₁ + ηgₜ; θₜ = θₜ₋₁ − vₜ, where gₜ = ∇L(θₜ₋₁), β ∈ [0,1) is the momentum coefficient, η is the learning rate, and vₜ is the velocity vector. Equivalently: θₜ = θₜ₋₁ − ηgₜ − β(θₜ₋₁ − θₜ₋₂). Geometric series interpretation: vₜ = ηΣₖ₌₀^∞ βᵏ gₜ₋ₖ — velocity is an exponentially decaying weighted average of all past gradients. In consistent gradient directions, gradients reinforce: vₜ → η/(1−β) · g (steady-state velocity). In oscillating directions, they cancel: momentum damps oscillations across the valley. Effective step size in a consistent direction: η/(1−β). For β=0.9 this is 10× amplification; for β=0.99 it gives 100× amplification.

```python
import numpy as np
import matplotlib.pyplot as plt

def sgd_momentum(grad_f, theta0, lr, beta, n_steps, f=None):
    """
    SGD with heavy ball momentum.
    vt = beta * v_{t-1} + lr * grad(theta_{t-1})
    theta_t = theta_{t-1} - vt
    """
    theta = np.array(theta0, dtype=np.float64)
    v = np.zeros_like(theta)
    history = {'theta': [theta.copy()], 'loss': [f(theta)] if f else []}

    for t in range(n_steps):
        g = grad_f(theta)
        v = beta * v + lr * g       # velocity accumulates
        theta = theta - v
        history['theta'].append(theta.copy())
        if f: history['loss'].append(f(theta))

    return history

# Compare vanilla GD vs momentum on ill-conditioned quadratic
# f(x,y) = 0.5*(x^2 + 100*y^2)  -- condition number kappa=100
f = lambda x: 0.5 * (x[0]**2 + 100*x[1]**2)
grad_f = lambda x: np.array([x[0], 100*x[1]])
x0 = np.array([10.0, 1.0])

L, mu = 100.0, 1.0
eta_gd = 2/(mu + L)       # optimal for GD
eta_mom = 2/(np.sqrt(mu) + np.sqrt(L))**2  # optimal for momentum
beta_mom = ((np.sqrt(L) - np.sqrt(mu))/(np.sqrt(L) + np.sqrt(mu)))**2

hist_gd = sgd_momentum(grad_f, x0, lr=eta_gd, beta=0, n_steps=300, f=f)
hist_mom = sgd_momentum(grad_f, x0, lr=eta_mom, beta=beta_mom, n_steps=300, f=f)

# Find steps to reach 1e-4 precision
steps_gd = next((i for i, l in enumerate(hist_gd['loss']) if l < 1e-4), 300)
steps_mom = next((i for i, l in enumerate(hist_mom['loss']) if l < 1e-4), 300)
print(f"GD:       {steps_gd} steps to 1e-4  (kappa={L/mu:.0f})")
print(f"Momentum: {steps_mom} steps to 1e-4  (speedup: {steps_gd/max(steps_mom,1):.1f}x)")
print(f"Effective momentum step size: eta/(1-beta) = {eta_mom/(1-beta_mom):.4f}")
print(f"Momentum coefficient beta = {beta_mom:.4f}")
```

## Exponential Moving Average as Low-Pass Filter

The EMA mₜ = βmₜ₋₁ + (1−β)xₜ is a recursive formula with explicit solution mₜ = (1−β)Σₖ₌₀^t βᵏ x_{t-k}. The weights (1−β)βᵏ sum to 1 (geometric series) and decay exponentially — recent values dominate. Effective window: τ = 1/(1−β). For β=0.9: window≈10 steps; β=0.99: window≈100 steps; β=0.999: window≈1000 steps. In frequency domain: EMA is a first-order IIR low-pass filter, passing low-frequency (slow trend) signals and attenuating high-frequency (noise) signals. The cutoff frequency is approximately (1−β)/(2π). Heavy ball momentum uses EMA of gradients: β=0.9 smooths gradient noise while preserving the trend direction, enabling larger effective step sizes than vanilla GD without the instability that would arise from simply using a larger learning rate directly.

```python
import numpy as np

def ema(values, beta=0.9, bias_correct=True):
    """
    Exponential moving average.
    m_t = beta * m_{t-1} + (1 - beta) * x_t
    With bias correction: m_hat_t = m_t / (1 - beta^t)
    """
    m = 0.0
    emas = []
    for t, x in enumerate(values, start=1):
        m = beta * m + (1 - beta) * x
        if bias_correct:
            m_hat = m / (1 - beta**t)
        else:
            m_hat = m
        emas.append(m_hat)
    return emas

# Demonstrate effective window size
beta = 0.9
effective_window = 1 / (1 - beta)
print(f"beta={beta}: effective window approx {effective_window:.0f} steps")

# Show EMA tracking a step function
n = 200
signal = np.concatenate([np.zeros(100), np.ones(100)])  # step at t=100
ema_90 = ema(signal, beta=0.9)
ema_99 = ema(signal, beta=0.99)

# Find tracking lag: steps to reach 63% of step value after the step
lag_90 = next((t for t, v in enumerate(ema_90[100:]) if v > 0.63), None) + 1
lag_99 = next((t for t, v in enumerate(ema_99[100:]) if v > 0.63), None) + 1
print(f"beta=0.9:  lag to 63% of step = {lag_90} steps  (approx 1/(1-beta)={1/(1-0.9):.0f})")
print(f"beta=0.99: lag to 63% of step = {lag_99} steps  (approx 1/(1-beta)={1/(1-0.99):.0f})")

# Bias correction importance for early steps
early_ema_no_bc = ema([1.0]*20, beta=0.9, bias_correct=False)
early_ema_bc = ema([1.0]*20, beta=0.9, bias_correct=True)
print(f"\nAfter 1 step with constant input=1: no-BC={early_ema_no_bc[0]:.3f} vs BC={early_ema_bc[0]:.3f}")
print(f"After 10 steps: no-BC={early_ema_no_bc[9]:.3f} vs BC={early_ema_bc[9]:.3f}")
```

## Accelerated Convergence: Momentum Achieves O(1/T²)

Nesterov's acceleration theorem: for L-smooth convex f, GD with momentum achieves f(θₜ)−f* ≤ O(L‖θ₀−θ*‖²/T²), compared to O(L‖θ₀−θ*‖²/T) for vanilla GD — a factor of T speedup. For strongly convex functions: momentum achieves O(exp(−T√(μ/L))) convergence vs O(exp(−T·μ/L)) for GD — linear rate but with √κ instead of κ dependence. Optimal momentum coefficient for convex smooth problems: β = (√κ−1)/(√κ+1) where κ = L/μ. Physical intuition: the ball picks up speed downhill (momentum accumulates) and uses inertia to cross small barriers and maintain forward progress. The deceleration near the minimum prevents overshoot: near θ*, the gradient reverses direction, applying a braking force that opposes the accumulated momentum and allows the optimizer to settle.

## ML Connections: EMA in Deep Learning

EMA appears in multiple critical ML components beyond optimization: (1) Adam's first moment: mₜ = β₁mₜ₋₁ + (1−β₁)gₜ (EMA of gradients with β₁=0.9). (2) DQN target network: θ⁻ = β·θ⁻ + (1−β)·θ — slow-moving copy of Q-network for stable Bellman targets (Mnih 2015). (3) BYOL (Grill 2020): online encoder θ updated by gradient; target encoder ξ = τ·ξ + (1−τ)·θ (momentum encoder), enabling self-supervised learning without negative samples. (4) Stochastic Weight Averaging (SWA, Izmailov 2018): θ_SWA = (1/n)Σθₜ (uniform average of SGD iterates), converges to flat minima and improves generalization. (5) EMA ensembles in diffusion models: a slow-moving copy of model weights is used for inference, yielding better sample quality than the current training checkpoint due to reduced noise sensitivity.

```python
import torch
import torch.nn as nn
import copy

class EMAModel:
    """
    Exponential Moving Average of model weights.
    Used in: BYOL target network, diffusion model inference, SWA.
    """
    def __init__(self, model, decay=0.999):
        self.decay = decay
        self.shadow = copy.deepcopy(model)
        # Freeze shadow -- gradients not needed
        for p in self.shadow.parameters():
            p.requires_grad_(False)

    @torch.no_grad()
    def update(self, model):
        """Update shadow weights: theta_ema = decay * theta_ema + (1-decay) * theta"""
        for ema_param, param in zip(self.shadow.parameters(), model.parameters()):
            ema_param.data.mul_(self.decay).add_(param.data, alpha=1.0 - self.decay)

    def get_model(self):
        return self.shadow

# Demonstrate EMA model tracking
class TinyNet(nn.Module):
    def __init__(self):
        super().__init__()
        self.fc = nn.Linear(4, 2)
    def forward(self, x):
        return self.fc(x)

model = TinyNet()
ema_model = EMAModel(model, decay=0.999)

# Simulate training: model weights change, EMA tracks slowly
optimizer = torch.optim.SGD(model.parameters(), lr=0.1)
x = torch.randn(16, 4)
y = torch.randint(0, 2, (16,))

for step in range(100):
    optimizer.zero_grad()
    loss = nn.CrossEntropyLoss()(model(x), y)
    loss.backward()
    optimizer.step()
    ema_model.update(model)

# Check: EMA weights are smoothed version of current weights
param = list(model.parameters())[0].data[0, 0].item()
ema_param = list(ema_model.get_model().parameters())[0].data[0, 0].item()
print(f"Current weight[0,0]: {param:.4f}")
print(f"EMA weight[0,0]:     {ema_param:.4f}")
print(f"Difference: {abs(param - ema_param):.4f} (EMA lags behind)")
print(f"Effective window: {1/(1-0.999):.0f} steps")
```

## Stochastic Weight Averaging (SWA)

SWA (Izmailov 2018) averages the weights of SGD iterates sampled periodically: θ_SWA = (1/n)Σθₜ. Key insight: the average of multiple points on a loss landscape valley typically lies at a flatter point than any individual iterate. SWA with a cyclical LR schedule works as follows: train with a high LR for k steps (explores the loss basin broadly), then step to low LR (sharp descent to a local minimum), take a weight snapshot; repeat. Average all snapshots at the end. Result: the final averaged parameters converge to a broad flat minimum with better test accuracy than using any single checkpoint. Implementation uses torch.optim.swa_utils.AveragedModel for weight tracking and update_bn(loader, swa_model) to recalculate batch normalization running statistics for the averaged weights — BN affine parameters are averaged but running statistics must be recomputed from data.

## Implementation Pitfalls

Momentum too high (β→1): the velocity term dominates and the optimizer overshoots, causing oscillations and eventual divergence. For convex problems, optimal β = (√κ−1)/(√κ+1). For neural networks, β=0.9 is standard; β=0.99 is used in some Adam variants. Setting β=0 recovers vanilla SGD. EMA decay too high: if decay=0.9999, the EMA lags 10,000 steps behind the current model — it tracks model changes too slowly during early training. Use lower decay (0.999) during early training and increase it toward 0.9999 during later training stages. SWA pitfall: if BN running statistics are not recalculated after weight averaging, the model produces incorrect normalizations because the averaged weights produce a different activation distribution than any individual checkpoint. Always call torch.optim.swa_utils.update_bn(loader, swa_model) after SWA averaging and before evaluation.

## Practical Guidance

Use β=0.9 as the default momentum coefficient for SGD with momentum — this is the standard setting for image classification (ResNet/ImageNet training). For Adam, β₁=0.9 and β₂=0.999 are standard defaults that rarely need tuning. Use SWA when training budget is fixed and you want 1-2% accuracy improvement for free: use AveragedModel from torch.optim.swa_utils and activate SWA for the final 20-25% of training epochs. For EMA target networks in RL and contrastive learning, start with decay=0.996 (used in BYOL) or 0.99 (used in DQN) — higher decay gives more stable targets but slower tracking of the current model. Monitor the ratio ‖v‖/‖θ‖ (velocity magnitude relative to parameter magnitude) to check momentum aggressiveness: if this ratio exceeds 1, momentum is too aggressive for the current LR combination.

```python
import torch
import torch.nn as nn
from torch.optim.swa_utils import AveragedModel, SWALR

def train_with_swa(model, train_loader, n_epochs=50, swa_start=40):
    """
    SWA training: regular SGD for first swa_start epochs,
    then switch to SWA mode with cyclical LR.
    """
    optimizer = torch.optim.SGD(model.parameters(), lr=0.1, momentum=0.9)
    swa_model = AveragedModel(model)
    swa_scheduler = SWALR(optimizer, swa_lr=0.05)
    criterion = nn.CrossEntropyLoss()

    for epoch in range(n_epochs):
        model.train()
        for X, y in train_loader:
            optimizer.zero_grad()
            loss = criterion(model(X), y)
            loss.backward()
            optimizer.step()

        if epoch >= swa_start:
            # SWA phase: average weights across epochs
            swa_model.update_parameters(model)
            swa_scheduler.step()
        else:
            # Warmup/cosine phase
            pass

    # CRITICAL: recalculate BN statistics for averaged model
    # (BN running stats are not averaged, only affine params)
    # torch.optim.swa_utils.update_bn(train_loader, swa_model)

    print(f"SWA training complete. Use swa_model for inference.")
    print("Remember: call update_bn(train_loader, swa_model) before evaluation!")
    return swa_model

print("SWA training function defined.")
print("Key insight: SWA averages weights of SGD snapshots -> flat minima -> better generalization.")
```

> **Momentum Amplifies Bad Gradients Too**: Momentum accumulates all past gradients — including incorrect ones at the start of training or after a sudden LR change. If the initial LR is too large (causing a bad first step), momentum will amplify that bad direction for the next 1/(1-beta) steps. Always warm up the learning rate for the first 5-10% of training. When resuming from a checkpoint, consider zeroing the momentum buffer (optimizer.state = {}) to avoid carrying over stale velocities that do not apply to the new LR schedule.

| Method | Convergence Rate (convex) | Convergence Rate (strongly convex) | Effective Step |
|---|---|---|---|
| Vanilla GD | O(1/T) | O(exp(-mu*T/L)) | eta |
| Heavy Ball (momentum) | O(1/T^2) (quadratic) | O(exp(-T*sqrt(mu/L))) | eta/(1-beta) |
| Nesterov (lookahead) | O(1/T^2) (general) | O(exp(-T*sqrt(mu/L))) | eta/(1-beta) |
| SWA (iterate avg) | O(1/T) | O(1/T) (convex rate) | N/A |
| EMA (exponential avg) | Biased estimator | Bias-variance tradeoff | N/A |

---

## Key Takeaways

- Heavy ball momentum vt = beta*v_{t-1} + eta*gt, theta_t = theta_{t-1} - vt amplifies consistent gradients by factor 1/(1-beta) and damps oscillating gradients.
- EMA mt = beta*m_{t-1} + (1-beta)*xt has effective window 1/(1-beta). Bias correction m_hat_t = mt/(1-beta^t) is essential for early timesteps.
- Momentum achieves O(1/T^2) convergence for convex smooth functions vs O(1/T) for GD — equivalent to sqrt(kappa) speedup for strongly convex problems.
- EMA appears in Adam (first moment), DQN target networks, BYOL contrastive learning, SWA, and diffusion model inference — a universal smoothing primitive.
- SWA averages SGD iterates sampled with cyclical LR, converging to flat minima with better generalization than any single checkpoint.
- For EMA models, always recalculate BN running statistics after weight averaging — they are not averaged, only affine parameters (gamma, beta) are.
- When resuming training after a checkpoint, consider zeroing the momentum buffer to avoid stale velocity contaminating the new LR regime.

