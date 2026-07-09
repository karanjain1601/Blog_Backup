---
title: "SGD and Stochastic Approximation"
slug: "sgd-stochastic-approximation"
description: "Rigorous treatment of SGD as stochastic approximation, variance analysis, Robbins-Monro convergence conditions, linear scaling rule, gradient accumulation, and SGD's implicit regularization toward flat minima."
tags: ["optimization", "sgd", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Stochastic gradient descent replaces the expensive full-gradient with a cheap noisy estimate, enabling training on massive datasets. But SGD is not merely gradient descent with some noise added. The stochasticity fundamentally changes the algorithm's behavior: it enables escape from sharp minima, provides implicit regularization, and requires different convergence analysis (Robbins-Monro conditions). Understanding SGD through the lens of stochastic approximation theory — variance, bias, step-size conditions, and the generalization gap — is essential for diagnosing training instability, tuning batch size and learning rate, and understanding why SGD often generalizes better than Adam on image classification tasks despite Adam’s faster convergence speed during training."}, {"type": "heading", "level": 2, "content": "Core Definition: Stochastic Gradient Estimates"}, {"type": "text", "content": "For a loss L(θ) = (1/n)Σᵢlᵢ(θ), the SGD gradient estimate using minibatch B⊆[n] of size B is ĝₜ = (1/|B|)Σᵢ∈B∇lᵢ(θₜ). Key properties: (1) Unbiasedness: E[ĝₜ|θₜ] = ∇L(θₜ). (2) Variance: Var[ĝₜ] = σ²/B where σ² = (1/n)Σᵢ‖∇lᵢ(θ)−∇L(θ)‖² is the per-sample gradient variance. (3) As B→n: full-batch gradient, zero noise. The gradient estimate enters the update: θₜ₊₁ = θₜ − ηₜĝₜ. The noise ζₜ = ĝₜ − ∇L(θₜ) has E[ζₜ]=0 (unbiased) but nonzero variance σ²/B. This noise fundamentally changes convergence behavior: SGD with constant LR does not converge to a stationary point but oscillates around one within a ball of radius proportional to ησ/√B."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport matplotlib.pyplot as plt\n\ndef sgd_variance_demo(n=1000, d=10, batch_sizes=[1, 32, 256, 1000], n_steps=500):\n    \"\"\"\n    Demonstrate gradient variance vs batch size.\n    Shows: Var[g_hat] approx sigma^2 / B (variance reduces linearly with B).\n    \"\"\"\n    np.random.seed(42)\n    X = np.random.randn(n, d)\n    w_true = np.random.randn(d)\n    y = X @ w_true + np.random.randn(n) * 0.5\n\n    # Full gradient (ground truth)\n    w = np.zeros(d)\n    grad_true = 2 * X.T @ (X @ w - y) / n\n\n    # Estimate gradient variance for each batch size\n    results = {}\n    for B in batch_sizes:\n        grad_estimates = []\n        for _ in range(200):  # 200 samples of gradient estimate\n            idx = np.random.choice(n, B, replace=False)\n            Xb, yb = X[idx], y[idx]\n            g = 2 * Xb.T @ (Xb @ w - yb) / B\n            grad_estimates.append(g)\n\n        grad_estimates = np.array(grad_estimates)\n        variance = grad_estimates.var(axis=0).mean()  # average variance across dims\n        results[B] = variance\n        print(f\"B={B:5d}: gradient variance = {variance:.4f}\")\n\n    # Verify linear relationship: Var proportional to 1/B\n    B_array = np.array(list(results.keys()))\n    var_array = np.array(list(results.values()))\n    sigma2_est = (var_array * B_array).mean()\n    print(f\"\\nEstimated sigma^2 = {sigma2_est:.4f}\")\n    for B, var in zip(B_array, var_array):\n        predicted = sigma2_est / B\n        print(f\"B={B}: actual={var:.4f}, predicted sigma^2/B={predicted:.4f}\")\n\nsgd_variance_demo()"}, {"type": "heading", "level": 2, "content": "Robbins-Monro Convergence Conditions"}, {"type": "text", "content": "The Robbins-Monro (1951) conditions for SGD convergence with decaying step sizes ηₜ are: (1) Σₜ ηₜ = ∞ (steps sum to infinity — ensures we can reach any point in parameter space); (2) Ση²ₜ < ∞ (sum of squared steps is finite — ensures variance shrinks fast enough for convergence). The canonical schedule ηₜ = η₀/t^α with α ∈ (0.5, 1] satisfies these conditions: Ση₀/t^α diverges (harmonic series for α=1), but Ση₀²/t^{2α} converges for 2α > 1. Under these conditions, SGD converges to a stationary point for non-convex f and to the global minimum for convex f. The decay must be slow enough (α ≤ 1) to explore the space, but fast enough (α > 0.5) to suppress noise and achieve convergence. Constant LR violates condition 2 — SGD oscillates permanently but can be averaged (Polyak-Ruppert averaging) for convergence."}, {"type": "code", "language": "python", "content": "import numpy as np\n\ndef sgd_with_lr_schedule(grad_fn, theta0, n, schedule='decay', n_steps=2000, eta0=0.1):\n    \"\"\"\n    Compare SGD with constant vs decaying learning rate.\n    Also demonstrates Polyak-Ruppert averaging.\n    \"\"\"\n    theta = theta0.copy()\n    theta_avg = theta0.copy()  # Polyak-Ruppert average\n    losses = []\n\n    # True optimum for comparison (assume quadratic)\n    f = lambda t: np.sum(t**2)\n\n    for t in range(1, n_steps + 1):\n        if schedule == 'decay':\n            eta_t = eta0 / np.sqrt(t)  # alpha = 0.5: just barely satisfies R-M\n        elif schedule == 'constant':\n            eta_t = eta0\n        else:\n            eta_t = eta0 / t  # alpha = 1: satisfies R-M strongly\n\n        # Noisy gradient (true gradient + noise)\n        g_true = grad_fn(theta)\n        noise = 0.1 * np.random.randn(len(theta))  # simulate SGD noise\n        g_noisy = g_true + noise\n\n        theta = theta - eta_t * g_noisy\n        # Polyak-Ruppert: running average of iterates\n        theta_avg = (theta_avg * (t - 1) + theta) / t\n\n        if t % 100 == 0:\n            losses.append((t, f(theta), f(theta_avg)))\n\n    return losses\n\n# Test on f(theta) = sum(theta^2), gradient = 2*theta\ngrad_fn = lambda theta: 2 * theta\ntheta0 = np.array([3.0, 2.0, 1.0])\n\nprint(\"Step  | theta_loss | theta_avg_loss | schedule\")\nfor schedule in ['constant', 'decay', 't-decay']:\n    losses = sgd_with_lr_schedule(grad_fn, theta0, n=100, schedule=schedule)\n    final = losses[-1]\n    print(f\"{final[0]} | {final[1]:.4e} | {final[2]:.4e} | {schedule}\")"}, {"type": "heading", "level": 2, "content": "Linear Scaling Rule and Batch Size"}, {"type": "text", "content": "The linear scaling rule (Goyal et al., Facebook 2017): when multiplying batch size by k, multiply the learning rate by k. Intuition: SGD with batch B and LR η updates using a gradient estimate with variance σ²/B. To maintain the same signal-to-noise ratio when doubling B, double η — this preserves gradient noise statistics per update. Formally: k steps of SGD with (B, η) approximate one step of SGD with (kB, kη) to first order in the step size. Limitations: the linear scaling rule breaks at very large batch sizes, beyond the critical batch size B_c ≈ σ²/‖∇L‖² — beyond this point, adding more samples does not proportionally reduce noise. Also, when using large batches (B>1024), always warm up the LR for the first few epochs, as the gradient variance is initially too high relative to the gradient signal to safely use the scaled LR."}, {"type": "heading", "level": 2, "content": "Implicit Regularization: Why SGD Generalizes Better"}, {"type": "text", "content": "Empirically, SGD generalizes better than full-batch GD on image classification, even at equivalent training loss. The theoretical explanation: SGD's gradient noise induces an implicit bias toward flatter minima. Intuitively, a sharp minimum (high curvature) is unstable under gradient noise — the noise kicks the optimizer out of sharp minima, and it eventually settles in flat minima (wide basins) that are more robust to perturbation. Formally, the SGD dynamics (with finite LR η) can be written as following the gradient of f + (η/4B)ΔL, where ΔL is the trace of the Hessian — this penalizes high-curvature regions. Flat minima have better test generalization by the PAC-Bayes perspective: a flat minimum means a larger neighborhood of parameters with good loss, implying the solution is robust to the distribution shift between training and test sets."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef compare_sgd_batch_generalization(n_train=500, n_test=500, n_epochs=100):\n    \"\"\"\n    Compare large-batch vs small-batch SGD on a simple overparameterized problem.\n    Shows: small batch generalizes better (flatter minima).\n    \"\"\"\n    torch.manual_seed(42)\n\n    # Synthetic data: 2-class classification\n    X_train = torch.randn(n_train, 20)\n    y_train = (X_train[:, 0] > 0).float().unsqueeze(1)\n    X_test = torch.randn(n_test, 20)\n    y_test = (X_test[:, 0] > 0).float().unsqueeze(1)\n\n    def make_model():\n        return nn.Sequential(nn.Linear(20, 64), nn.ReLU(),\n                              nn.Linear(64, 64), nn.ReLU(),\n                              nn.Linear(64, 1), nn.Sigmoid())\n\n    def train(model, batch_size, lr, n_epochs):\n        opt = torch.optim.SGD(model.parameters(), lr=lr)\n        criterion = nn.BCELoss()\n        for epoch in range(n_epochs):\n            idx = torch.randperm(n_train)\n            for start in range(0, n_train, batch_size):\n                Xb = X_train[idx[start:start+batch_size]]\n                yb = y_train[idx[start:start+batch_size]]\n                opt.zero_grad()\n                loss = criterion(model(Xb), yb)\n                loss.backward()\n                opt.step()\n        with torch.no_grad():\n            train_acc = ((model(X_train) > 0.5) == y_train).float().mean()\n            test_acc = ((model(X_test) > 0.5) == y_test).float().mean()\n        return train_acc.item(), test_acc.item()\n\n    # Linear scaling rule: large batch uses proportionally larger LR\n    for batch_size, lr in [(8, 0.01), (256, 0.32)]:\n        model = make_model()\n        train_acc, test_acc = train(model, batch_size, lr, n_epochs)\n        gen_gap = train_acc - test_acc\n        print(f\"B={batch_size:4d} lr={lr:.2f}: train={train_acc:.3f} test={test_acc:.3f} gap={gen_gap:.3f}\")\n\ncompare_sgd_batch_generalization()"}, {"type": "heading", "level": 2, "content": "Gradient Accumulation for Simulating Large Batches"}, {"type": "text", "content": "When GPU memory limits batch size, gradient accumulation simulates larger effective batches: run B_micro micro-batches through forward and backward passes, accumulate gradients, then take one optimizer step. Effective batch size = B_micro × n_accumulation_steps. Critical implementation detail: divide loss by n_accumulation_steps before the backward pass (or set reduction='mean' within each micro-batch), otherwise gradients are scaled by n_accumulation_steps relative to the expected magnitude. This scaling matters especially for gradient clipping: always clip after accumulation using the accumulated gradient norm, not the per-micro-batch norm. This approach works identically to true large batch for deterministic models, but dropout and batch normalization behavior differ slightly (BN running statistics are computed on the micro-batch size, not the full accumulated effective batch)."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn as nn\n\ndef training_loop_with_gradient_accumulation(\n    model, optimizer, dataloader, n_accumulation_steps=4, clip_norm=1.0\n):\n    \"\"\"\n    Training loop with gradient accumulation.\n    Effective batch size = loader batch_size * n_accumulation_steps.\n    \"\"\"\n    model.train()\n    criterion = nn.CrossEntropyLoss()\n    total_loss = 0.0\n    optimizer.zero_grad()\n\n    for step, (X, y) in enumerate(dataloader):\n        # Forward pass on micro-batch\n        logits = model(X)\n        # Divide loss by accumulation steps so gradients are correct scale\n        loss = criterion(logits, y) / n_accumulation_steps\n        loss.backward()\n\n        total_loss += loss.item() * n_accumulation_steps\n\n        # Every n_accumulation_steps, update parameters\n        if (step + 1) % n_accumulation_steps == 0:\n            # Clip AFTER accumulation (uses accumulated gradient norm)\n            torch.nn.utils.clip_grad_norm_(model.parameters(), clip_norm)\n            optimizer.step()\n            optimizer.zero_grad()\n\n            effective_step = (step + 1) // n_accumulation_steps\n            avg_loss = total_loss / n_accumulation_steps\n            if effective_step % 10 == 0:\n                print(f\"Step {effective_step}: loss={avg_loss:.4f}\")\n            total_loss = 0.0\n\n    # Handle remaining micro-batches at end of epoch\n    if (step + 1) % n_accumulation_steps != 0:\n        torch.nn.utils.clip_grad_norm_(model.parameters(), clip_norm)\n        optimizer.step()\n        optimizer.zero_grad()\n\nprint(\"Gradient accumulation training loop defined.\")\nprint(\"Key: divide loss by n_accumulation_steps BEFORE backward.\")\nprint(\"Key: clip gradients AFTER accumulation, not per micro-batch.\")"}, {"type": "heading", "level": 2, "content": "Implementation Pitfalls"}, {"type": "text", "content": "Not shuffling data: if samples are ordered by class, cyclic SGD sees correlated batches, introducing systematic bias in gradient estimates. Always shuffle each epoch with torch.randperm(n). Forgetting to scale loss in gradient accumulation: if loss is not divided by n_accumulation_steps, effective LR increases by that factor — causing instability and potential divergence. Using batch norm with very small effective batch size: BN with B<8 produces noisy mean and variance statistics that hurt performance significantly. Use Group Norm or Layer Norm for small-batch training instead. Decreasing LR too fast: ηₜ = η₀/t (alpha=1) satisfies Robbins-Monro theoretically but converges very slowly in practice because the LR drops below the useful range quickly. Use ηₜ = η₀/√t or cosine annealing for better empirical performance and faster practical convergence."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Start with B=256 and LR=0.1 for image classification with SGD+momentum. Scale both proportionally for different hardware (linear scaling rule up to B_critical ≈ 8192 for ImageNet). Use linear warmup over 5 epochs when using large batches (B>1024) to avoid instability from high initial gradient variance. Prefer cosine annealing over step decay — it produces smoother loss curves and avoids the need for manual schedule tuning. Monitor gradient variance across training steps (compute standard deviation of gradient estimates over several consecutive steps): if std/mean < 0.1, you can safely increase batch size; if > 10, the gradient is too noisy and batch size should increase. For NLP tasks with sparse features, prefer Adam over SGD — gradient variance is structurally higher in NLP due to sparse token gradients."}, {"type": "callout", "title": "Constant LR Prevents True Convergence", "content": "With constant learning rate eta, SGD converges to within a ball of radius O(eta*sigma/sqrt(B)) around the minimum, not to the exact minimum. To converge to a stationary point, you need decaying LR (Robbins-Monro) or Polyak-Ruppert averaging (average of all iterates). In practice, cosine annealing to a very small LR (1% of peak) approximates convergence. Alternatively, run SGD with constant LR and switch to full-batch GD for the last few steps for exact convergence."}, {"type": "table", "headers": ["Batch Size B", "Gradient Variance", "Steps/Epoch", "Generalization", "Practical Use"], "rows": [["1 (true SGD)", "sigma^2", "n steps", "Best (flattest minima)", "Rarely used (slow)"], ["32-64 (small)", "sigma^2/32-64", "n/B steps", "Very good", "Small models, RL"], ["256-1024 (medium)", "sigma^2/256-1024", "n/B steps", "Good", "Standard ImageNet, NLP"], ["4096-32768 (large)", "sigma^2/4096-32768", "n/B steps", "Reduced (sharper minima)", "Distributed training, requires warmup"], ["Full batch (n)", "0 (exact)", "1 step", "Worst generalization", "Convex problems only"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "items": ["SGD gradient estimate g_hat = (1/B)*sum(grad(l_i)) is unbiased: E[g_hat]=grad(L). Variance is sigma^2/B — reduces linearly with batch size.", "Robbins-Monro conditions for convergence with decaying LR: sum(eta_t)=infinity (can reach any point) and sum(eta_t^2)<infinity (variance shrinks). Satisfied by eta_t=eta_0/t^alpha for alpha in (0.5,1].", "Linear scaling rule: multiply LR by k when multiplying batch size by k. Breaks above critical batch size B_c approx sigma^2/||grad(L)||^2.", "SGD noise implicitly regularizes toward flat minima — these empirically generalize better than full-batch GD. The noise acts as a penalty on the Hessian trace.", "Gradient accumulation simulates large batches: divide loss by n_accumulation_steps, clip after full accumulation, not per micro-batch.", "Constant LR SGD oscillates around minimum (does not converge to it). Use decaying LR or Polyak-Ruppert averaging (average of all iterates) for exact convergence.", "Always shuffle data each epoch. Not shuffling with correlated mini-batches introduces gradient bias and slows convergence significantly."]}]"
---

# SGD and Stochastic Approximation

Stochastic gradient descent replaces the expensive full-gradient with a cheap noisy estimate, enabling training on massive datasets. But SGD is not merely gradient descent with some noise added. The stochasticity fundamentally changes the algorithm's behavior: it enables escape from sharp minima, provides implicit regularization, and requires different convergence analysis (Robbins-Monro conditions). Understanding SGD through the lens of stochastic approximation theory — variance, bias, step-size conditions, and the generalization gap — is essential for diagnosing training instability, tuning batch size and learning rate, and understanding why SGD often generalizes better than Adam on image classification tasks despite Adam’s faster convergence speed during training.

## Core Definition: Stochastic Gradient Estimates

For a loss L(θ) = (1/n)Σᵢlᵢ(θ), the SGD gradient estimate using minibatch B⊆[n] of size B is ĝₜ = (1/|B|)Σᵢ∈B∇lᵢ(θₜ). Key properties: (1) Unbiasedness: E[ĝₜ|θₜ] = ∇L(θₜ). (2) Variance: Var[ĝₜ] = σ²/B where σ² = (1/n)Σᵢ‖∇lᵢ(θ)−∇L(θ)‖² is the per-sample gradient variance. (3) As B→n: full-batch gradient, zero noise. The gradient estimate enters the update: θₜ₊₁ = θₜ − ηₜĝₜ. The noise ζₜ = ĝₜ − ∇L(θₜ) has E[ζₜ]=0 (unbiased) but nonzero variance σ²/B. This noise fundamentally changes convergence behavior: SGD with constant LR does not converge to a stationary point but oscillates around one within a ball of radius proportional to ησ/√B.

```python
import numpy as np
import matplotlib.pyplot as plt

def sgd_variance_demo(n=1000, d=10, batch_sizes=[1, 32, 256, 1000], n_steps=500):
    """
    Demonstrate gradient variance vs batch size.
    Shows: Var[g_hat] approx sigma^2 / B (variance reduces linearly with B).
    """
    np.random.seed(42)
    X = np.random.randn(n, d)
    w_true = np.random.randn(d)
    y = X @ w_true + np.random.randn(n) * 0.5

    # Full gradient (ground truth)
    w = np.zeros(d)
    grad_true = 2 * X.T @ (X @ w - y) / n

    # Estimate gradient variance for each batch size
    results = {}
    for B in batch_sizes:
        grad_estimates = []
        for _ in range(200):  # 200 samples of gradient estimate
            idx = np.random.choice(n, B, replace=False)
            Xb, yb = X[idx], y[idx]
            g = 2 * Xb.T @ (Xb @ w - yb) / B
            grad_estimates.append(g)

        grad_estimates = np.array(grad_estimates)
        variance = grad_estimates.var(axis=0).mean()  # average variance across dims
        results[B] = variance
        print(f"B={B:5d}: gradient variance = {variance:.4f}")

    # Verify linear relationship: Var proportional to 1/B
    B_array = np.array(list(results.keys()))
    var_array = np.array(list(results.values()))
    sigma2_est = (var_array * B_array).mean()
    print(f"\nEstimated sigma^2 = {sigma2_est:.4f}")
    for B, var in zip(B_array, var_array):
        predicted = sigma2_est / B
        print(f"B={B}: actual={var:.4f}, predicted sigma^2/B={predicted:.4f}")

sgd_variance_demo()
```

## Robbins-Monro Convergence Conditions

The Robbins-Monro (1951) conditions for SGD convergence with decaying step sizes ηₜ are: (1) Σₜ ηₜ = ∞ (steps sum to infinity — ensures we can reach any point in parameter space); (2) Ση²ₜ < ∞ (sum of squared steps is finite — ensures variance shrinks fast enough for convergence). The canonical schedule ηₜ = η₀/t^α with α ∈ (0.5, 1] satisfies these conditions: Ση₀/t^α diverges (harmonic series for α=1), but Ση₀²/t^{2α} converges for 2α > 1. Under these conditions, SGD converges to a stationary point for non-convex f and to the global minimum for convex f. The decay must be slow enough (α ≤ 1) to explore the space, but fast enough (α > 0.5) to suppress noise and achieve convergence. Constant LR violates condition 2 — SGD oscillates permanently but can be averaged (Polyak-Ruppert averaging) for convergence.

```python
import numpy as np

def sgd_with_lr_schedule(grad_fn, theta0, n, schedule='decay', n_steps=2000, eta0=0.1):
    """
    Compare SGD with constant vs decaying learning rate.
    Also demonstrates Polyak-Ruppert averaging.
    """
    theta = theta0.copy()
    theta_avg = theta0.copy()  # Polyak-Ruppert average
    losses = []

    # True optimum for comparison (assume quadratic)
    f = lambda t: np.sum(t**2)

    for t in range(1, n_steps + 1):
        if schedule == 'decay':
            eta_t = eta0 / np.sqrt(t)  # alpha = 0.5: just barely satisfies R-M
        elif schedule == 'constant':
            eta_t = eta0
        else:
            eta_t = eta0 / t  # alpha = 1: satisfies R-M strongly

        # Noisy gradient (true gradient + noise)
        g_true = grad_fn(theta)
        noise = 0.1 * np.random.randn(len(theta))  # simulate SGD noise
        g_noisy = g_true + noise

        theta = theta - eta_t * g_noisy
        # Polyak-Ruppert: running average of iterates
        theta_avg = (theta_avg * (t - 1) + theta) / t

        if t % 100 == 0:
            losses.append((t, f(theta), f(theta_avg)))

    return losses

# Test on f(theta) = sum(theta^2), gradient = 2*theta
grad_fn = lambda theta: 2 * theta
theta0 = np.array([3.0, 2.0, 1.0])

print("Step  | theta_loss | theta_avg_loss | schedule")
for schedule in ['constant', 'decay', 't-decay']:
    losses = sgd_with_lr_schedule(grad_fn, theta0, n=100, schedule=schedule)
    final = losses[-1]
    print(f"{final[0]} | {final[1]:.4e} | {final[2]:.4e} | {schedule}")
```

## Linear Scaling Rule and Batch Size

The linear scaling rule (Goyal et al., Facebook 2017): when multiplying batch size by k, multiply the learning rate by k. Intuition: SGD with batch B and LR η updates using a gradient estimate with variance σ²/B. To maintain the same signal-to-noise ratio when doubling B, double η — this preserves gradient noise statistics per update. Formally: k steps of SGD with (B, η) approximate one step of SGD with (kB, kη) to first order in the step size. Limitations: the linear scaling rule breaks at very large batch sizes, beyond the critical batch size B_c ≈ σ²/‖∇L‖² — beyond this point, adding more samples does not proportionally reduce noise. Also, when using large batches (B>1024), always warm up the LR for the first few epochs, as the gradient variance is initially too high relative to the gradient signal to safely use the scaled LR.

## Implicit Regularization: Why SGD Generalizes Better

Empirically, SGD generalizes better than full-batch GD on image classification, even at equivalent training loss. The theoretical explanation: SGD's gradient noise induces an implicit bias toward flatter minima. Intuitively, a sharp minimum (high curvature) is unstable under gradient noise — the noise kicks the optimizer out of sharp minima, and it eventually settles in flat minima (wide basins) that are more robust to perturbation. Formally, the SGD dynamics (with finite LR η) can be written as following the gradient of f + (η/4B)ΔL, where ΔL is the trace of the Hessian — this penalizes high-curvature regions. Flat minima have better test generalization by the PAC-Bayes perspective: a flat minimum means a larger neighborhood of parameters with good loss, implying the solution is robust to the distribution shift between training and test sets.

```python
import torch
import torch.nn as nn
import numpy as np

def compare_sgd_batch_generalization(n_train=500, n_test=500, n_epochs=100):
    """
    Compare large-batch vs small-batch SGD on a simple overparameterized problem.
    Shows: small batch generalizes better (flatter minima).
    """
    torch.manual_seed(42)

    # Synthetic data: 2-class classification
    X_train = torch.randn(n_train, 20)
    y_train = (X_train[:, 0] > 0).float().unsqueeze(1)
    X_test = torch.randn(n_test, 20)
    y_test = (X_test[:, 0] > 0).float().unsqueeze(1)

    def make_model():
        return nn.Sequential(nn.Linear(20, 64), nn.ReLU(),
                              nn.Linear(64, 64), nn.ReLU(),
                              nn.Linear(64, 1), nn.Sigmoid())

    def train(model, batch_size, lr, n_epochs):
        opt = torch.optim.SGD(model.parameters(), lr=lr)
        criterion = nn.BCELoss()
        for epoch in range(n_epochs):
            idx = torch.randperm(n_train)
            for start in range(0, n_train, batch_size):
                Xb = X_train[idx[start:start+batch_size]]
                yb = y_train[idx[start:start+batch_size]]
                opt.zero_grad()
                loss = criterion(model(Xb), yb)
                loss.backward()
                opt.step()
        with torch.no_grad():
            train_acc = ((model(X_train) > 0.5) == y_train).float().mean()
            test_acc = ((model(X_test) > 0.5) == y_test).float().mean()
        return train_acc.item(), test_acc.item()

    # Linear scaling rule: large batch uses proportionally larger LR
    for batch_size, lr in [(8, 0.01), (256, 0.32)]:
        model = make_model()
        train_acc, test_acc = train(model, batch_size, lr, n_epochs)
        gen_gap = train_acc - test_acc
        print(f"B={batch_size:4d} lr={lr:.2f}: train={train_acc:.3f} test={test_acc:.3f} gap={gen_gap:.3f}")

compare_sgd_batch_generalization()
```

## Gradient Accumulation for Simulating Large Batches

When GPU memory limits batch size, gradient accumulation simulates larger effective batches: run B_micro micro-batches through forward and backward passes, accumulate gradients, then take one optimizer step. Effective batch size = B_micro × n_accumulation_steps. Critical implementation detail: divide loss by n_accumulation_steps before the backward pass (or set reduction='mean' within each micro-batch), otherwise gradients are scaled by n_accumulation_steps relative to the expected magnitude. This scaling matters especially for gradient clipping: always clip after accumulation using the accumulated gradient norm, not the per-micro-batch norm. This approach works identically to true large batch for deterministic models, but dropout and batch normalization behavior differ slightly (BN running statistics are computed on the micro-batch size, not the full accumulated effective batch).

```python
import torch
import torch.nn as nn

def training_loop_with_gradient_accumulation(
    model, optimizer, dataloader, n_accumulation_steps=4, clip_norm=1.0
):
    """
    Training loop with gradient accumulation.
    Effective batch size = loader batch_size * n_accumulation_steps.
    """
    model.train()
    criterion = nn.CrossEntropyLoss()
    total_loss = 0.0
    optimizer.zero_grad()

    for step, (X, y) in enumerate(dataloader):
        # Forward pass on micro-batch
        logits = model(X)
        # Divide loss by accumulation steps so gradients are correct scale
        loss = criterion(logits, y) / n_accumulation_steps
        loss.backward()

        total_loss += loss.item() * n_accumulation_steps

        # Every n_accumulation_steps, update parameters
        if (step + 1) % n_accumulation_steps == 0:
            # Clip AFTER accumulation (uses accumulated gradient norm)
            torch.nn.utils.clip_grad_norm_(model.parameters(), clip_norm)
            optimizer.step()
            optimizer.zero_grad()

            effective_step = (step + 1) // n_accumulation_steps
            avg_loss = total_loss / n_accumulation_steps
            if effective_step % 10 == 0:
                print(f"Step {effective_step}: loss={avg_loss:.4f}")
            total_loss = 0.0

    # Handle remaining micro-batches at end of epoch
    if (step + 1) % n_accumulation_steps != 0:
        torch.nn.utils.clip_grad_norm_(model.parameters(), clip_norm)
        optimizer.step()
        optimizer.zero_grad()

print("Gradient accumulation training loop defined.")
print("Key: divide loss by n_accumulation_steps BEFORE backward.")
print("Key: clip gradients AFTER accumulation, not per micro-batch.")
```

## Implementation Pitfalls

Not shuffling data: if samples are ordered by class, cyclic SGD sees correlated batches, introducing systematic bias in gradient estimates. Always shuffle each epoch with torch.randperm(n). Forgetting to scale loss in gradient accumulation: if loss is not divided by n_accumulation_steps, effective LR increases by that factor — causing instability and potential divergence. Using batch norm with very small effective batch size: BN with B<8 produces noisy mean and variance statistics that hurt performance significantly. Use Group Norm or Layer Norm for small-batch training instead. Decreasing LR too fast: ηₜ = η₀/t (alpha=1) satisfies Robbins-Monro theoretically but converges very slowly in practice because the LR drops below the useful range quickly. Use ηₜ = η₀/√t or cosine annealing for better empirical performance and faster practical convergence.

## Practical Guidance

Start with B=256 and LR=0.1 for image classification with SGD+momentum. Scale both proportionally for different hardware (linear scaling rule up to B_critical ≈ 8192 for ImageNet). Use linear warmup over 5 epochs when using large batches (B>1024) to avoid instability from high initial gradient variance. Prefer cosine annealing over step decay — it produces smoother loss curves and avoids the need for manual schedule tuning. Monitor gradient variance across training steps (compute standard deviation of gradient estimates over several consecutive steps): if std/mean < 0.1, you can safely increase batch size; if > 10, the gradient is too noisy and batch size should increase. For NLP tasks with sparse features, prefer Adam over SGD — gradient variance is structurally higher in NLP due to sparse token gradients.

> **Constant LR Prevents True Convergence**: With constant learning rate eta, SGD converges to within a ball of radius O(eta*sigma/sqrt(B)) around the minimum, not to the exact minimum. To converge to a stationary point, you need decaying LR (Robbins-Monro) or Polyak-Ruppert averaging (average of all iterates). In practice, cosine annealing to a very small LR (1% of peak) approximates convergence. Alternatively, run SGD with constant LR and switch to full-batch GD for the last few steps for exact convergence.

| Batch Size B | Gradient Variance | Steps/Epoch | Generalization | Practical Use |
|---|---|---|---|---|
| 1 (true SGD) | sigma^2 | n steps | Best (flattest minima) | Rarely used (slow) |
| 32-64 (small) | sigma^2/32-64 | n/B steps | Very good | Small models, RL |
| 256-1024 (medium) | sigma^2/256-1024 | n/B steps | Good | Standard ImageNet, NLP |
| 4096-32768 (large) | sigma^2/4096-32768 | n/B steps | Reduced (sharper minima) | Distributed training, requires warmup |
| Full batch (n) | 0 (exact) | 1 step | Worst generalization | Convex problems only |

---

## Key Takeaways

- SGD gradient estimate g_hat = (1/B)*sum(grad(l_i)) is unbiased: E[g_hat]=grad(L). Variance is sigma^2/B — reduces linearly with batch size.
- Robbins-Monro conditions for convergence with decaying LR: sum(eta_t)=infinity (can reach any point) and sum(eta_t^2)<infinity (variance shrinks). Satisfied by eta_t=eta_0/t^alpha for alpha in (0.5,1].
- Linear scaling rule: multiply LR by k when multiplying batch size by k. Breaks above critical batch size B_c approx sigma^2/||grad(L)||^2.
- SGD noise implicitly regularizes toward flat minima — these empirically generalize better than full-batch GD. The noise acts as a penalty on the Hessian trace.
- Gradient accumulation simulates large batches: divide loss by n_accumulation_steps, clip after full accumulation, not per micro-batch.
- Constant LR SGD oscillates around minimum (does not converge to it). Use decaying LR or Polyak-Ruppert averaging (average of all iterates) for exact convergence.
- Always shuffle data each epoch. Not shuffling with correlated mini-batches introduces gradient bias and slows convergence significantly.

