---
title: "Gradient Descent — Convergence Analysis and Step Size"
slug: "gradient-descent"
description: "Rigorous treatment of gradient descent convergence theory including L-smooth functions, convex and strongly convex rates, saddle points in non-convex settings, gradient flow ODE, and the Polyak-Łojasiewicz condition."
tags: ["optimization", "calculus", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Gradient descent is the backbone of virtually every machine learning optimizer. Yet most practitioners treat it as a black box: subtract the gradient, scale by learning rate, repeat. A rigorous understanding — convergence rates, smoothness conditions, saddle point dynamics, and the relationship between discrete updates and continuous gradient flow — is essential for choosing learning rates correctly, diagnosing training failures, and understanding why more sophisticated optimizers (Adam, Lion) help. This note covers: update rule derivation, L-smooth convergence guarantees, convex vs strongly convex rates, non-convex landscape difficulties, and the gradient flow ODE perspective."}, {"type": "heading", "level": 2, "content": "Core Definition: The Update Rule"}, {"type": "text", "content": "The gradient descent update for minimizing f: ℝⁿ → ℝ is θₜ₊₁ = θₜ − η∇f(θₜ), where η > 0 is the learning rate (step size). The negative gradient direction −∇f(θ) is the steepest descent direction (by Cauchy-Schwarz: the direction maximally decreasing f per unit distance). Each step decreases f by approximately η‖∇f‖² (to first order): f(θₜ − η∇f) ≈ f(θ) − η‖∇f‖². The continuous analogue is the gradient flow ODE: dθ/dt = −∇f(θ), which converges to a stationary point as t→∞ under mild conditions. Discrete GD approximates this ODE with step size η as the temporal discretization parameter."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport matplotlib.pyplot as plt\n\ndef gradient_descent(grad_f, x0, lr, n_steps, f=None):\n    \"\"\"Basic gradient descent. Returns trajectory and loss history.\"\"\"\n    x = np.array(x0, dtype=np.float64)\n    trajectory = [x.copy()]\n    losses = [f(x)] if f else []\n\n    for t in range(n_steps):\n        g = grad_f(x)\n        x = x - lr * g\n        trajectory.append(x.copy())\n        if f: losses.append(f(x))\n\n    return np.array(trajectory), losses\n\n# Example: minimize f(x, y) = x^2 + 4y^2 (condition number kappa = 4)\nf = lambda x: x[0]**2 + 4*x[1]**2\ngrad_f = lambda x: np.array([2*x[0], 8*x[1]])\n\nx0 = np.array([3.0, 2.0])\n\n# Three learning rates: optimal eta = 1/L = 1/8, too small, too large\nfor lr, label in [(0.001, 'too small'), (0.125, 'optimal eta=1/L'), (0.26, 'too large')]:\n    traj, losses = gradient_descent(grad_f, x0, lr=lr, n_steps=200, f=f)\n    if losses:\n        final = losses[-1]\n        print(f\"lr={lr} ({label}): final loss={final:.6f} after 200 steps\")\n    else:\n        print(f\"lr={lr} ({label}): diverged\")\n\n# Exact convergence rate for strongly convex: f(theta_T) - f* <= (1 - 2*eta*mu*L/(mu+L))^T * (f(theta_0) - f*)\n# For f(x,y) = x^2 + 4y^2: mu = 2 (min eigenvalue of Hessian), L = 8 (max eigenvalue)\nmu, L = 2.0, 8.0\neta_opt = 2 / (mu + L)  # Optimal step for strongly convex: 2/(mu+L)\nrho = (L - mu) / (L + mu)  # Convergence rate\nprint(f\"\\nOptimal eta for strongly convex: {eta_opt:.4f}, rho = {rho:.4f}\")\nprint(f\"Steps to 1e-6 precision: {int(np.log(1e-6) / np.log(rho)) + 1}\")"}, {"type": "heading", "level": 2, "content": "L-Smoothness and Convergence Guarantees"}, {"type": "text", "content": "A function f is L-smooth (L-Lipschitz gradient) if ‖∇f(x) − ∇f(y)‖ ≤ L‖x−y‖ for all x,y. Equivalently: f(y) ≤ f(x) + ∇f(x)ᵀ(y−x) + L/2‖y−x‖² (the gradient descent lemma). This quadratic upper bound guarantees that a step η = 1/L always decreases f: f(θ−η∇f) ≤ f(θ) − (1/2L)‖∇f(θ)‖². For convex L-smooth f: gradient descent with η ≤ 1/L achieves f(θₜ) − f* ≤ ‖θ₀−θ*‖²/(2ηT) — rate O(1/T). For μ-strongly convex L-smooth f: f(θₜ) − f* ≤ (1−2ημL/(μ+L))ᵀ(f(θ₀)−f*) — linear rate O(ρᵀ) where ρ = (κ−1)/(κ+1) < 1, κ = L/μ. Strong convexity provides the pull toward minimum that enables linear convergence."}, {"type": "code", "language": "python", "content": "import numpy as np\n\ndef verify_l_smoothness(f, grad_f, x, y, L_candidate):\n    \"\"\"Check if L-smoothness inequality holds at x, y.\"\"\"\n    lhs = f(y)\n    rhs = f(x) + grad_f(x) @ (y - x) + L_candidate/2 * np.linalg.norm(y-x)**2\n    return lhs <= rhs + 1e-10, lhs, rhs\n\ndef convergence_rate_analysis(f, grad_f, x0, f_star, mu, L, n_steps=500):\n    \"\"\"\n    Analyze convergence rate for L-smooth strongly convex function.\n    Expected: linear rate rho = (L-mu)/(L+mu).\n    \"\"\"\n    eta = 2.0 / (mu + L)  # Optimal step size for strongly convex\n    x = x0.copy()\n    gaps = []\n\n    for t in range(n_steps):\n        gap = f(x) - f_star\n        gaps.append(gap)\n        if gap < 1e-12: break\n        x = x - eta * grad_f(x)\n\n    # Fit empirical convergence rate\n    rho_theory = (L - mu) / (L + mu)\n    rho_empirical = (gaps[-1] / gaps[0]) ** (1 / len(gaps))\n\n    return np.array(gaps), rho_theory, rho_empirical\n\n# f(x) = x^T A x / 2  where A = diag(2, 4, 6, 8)  (strongly convex, L-smooth)\nA = np.diag([2.0, 4.0, 6.0, 8.0])\nf = lambda x: 0.5 * x @ A @ x\ngrad_f = lambda x: A @ x\nx0 = np.array([3.0, 2.0, 1.0, 0.5])\nf_star = 0.0  # minimum at origin\nmu, L = 2.0, 8.0  # min and max eigenvalues of A\n\ngaps, rho_th, rho_emp = convergence_rate_analysis(f, grad_f, x0, f_star, mu, L)\nprint(f\"Theoretical rate rho = {rho_th:.4f}\")\nprint(f\"Empirical rate rho = {rho_emp:.4f}\")\nprint(f\"Steps to 1e-6: theoretical {int(np.log(1e-6) / np.log(rho_th))+1}, actual {len(gaps)}\")\n\n# Verify L-smoothness\nx_test = np.array([1.0, 1.0, 1.0, 1.0])\ny_test = x_test + 0.1 * np.random.randn(4)\nok, lhs, rhs = verify_l_smoothness(f, grad_f, x_test, y_test, L)\nprint(f\"\\nL-smoothness check: {ok}  (lhs={lhs:.4f} <= rhs={rhs:.4f})\")"}, {"type": "heading", "level": 2, "content": "Non-Convex Landscapes: Saddle Points and Local Minima"}, {"type": "text", "content": "For non-convex f (all neural networks), GD is not guaranteed to find the global minimum. Two obstacles arise: (1) Local minima — GD converges to a local stationary point ∇f(θ*)=0. However, for over-parameterized networks, recent theory (e.g., NTK regime) suggests that local minima are often near-global. (2) Saddle points — critical points where some Hessian eigenvalues are negative (directions of decrease exist). In high dimensions, saddle points are exponentially more common than local minima (Bhojanapalli et al.). The Polyak-Łojasiewicz (PL) condition provides non-convex convergence: if ‖∇f‖² ≥ 2μ(f−f*), then GD converges linearly even without convexity. Over-parameterized neural networks often satisfy PL empirically, which helps explain why GD finds good solutions despite the non-convex landscape."}, {"type": "heading", "level": 2, "content": "ML Connections: Batch GD vs Mini-Batch vs SGD"}, {"type": "text", "content": "Full-batch GD computes the gradient over the entire dataset. For n samples and d parameters: cost O(nd) per step. Mini-batch GD uses a random subset B of size B: gradient estimate ĝ = (1/B)Σ_{i∈B}∇Lᵢ(θ). This is an unbiased estimate of the true gradient: E[ĝ] = ∇L. Variance: Var[ĝ] ≈ σ²/B where σ² is the per-sample gradient variance. SGD (B=1) has highest variance but best parallelism and implicit regularization. Minibatch SGD with B=256–4096 is the practical sweet spot: enough noise for generalization, enough signal for stable convergence. The linear scaling rule (Goyal et al. 2017): multiply LR by B/256 when scaling batch size — this preserves gradient noise statistics and keeps the effective update magnitude constant across different hardware configurations."}, {"type": "code", "language": "python", "content": "import numpy as np\n\ndef minibatch_sgd(loss_fn, grad_fn, theta0, X, y, lr, batch_size, n_epochs):\n    \"\"\"\n    Minibatch SGD with data shuffling per epoch.\n    Returns: final theta, per-epoch average loss.\n    \"\"\"\n    theta = theta0.copy()\n    n = len(X)\n    epoch_losses = []\n\n    for epoch in range(n_epochs):\n        # Shuffle data each epoch (critical for convergence)\n        idx = np.random.permutation(n)\n        X_shuf, y_shuf = X[idx], y[idx]\n\n        batch_losses = []\n        for start in range(0, n, batch_size):\n            end = min(start + batch_size, n)\n            Xb = X_shuf[start:end]\n            yb = y_shuf[start:end]\n\n            g = grad_fn(theta, Xb, yb)\n            theta = theta - lr * g\n            batch_losses.append(loss_fn(theta, Xb, yb))\n\n        epoch_losses.append(np.mean(batch_losses))\n\n    return theta, epoch_losses\n\n# Linear regression: L(w) = ||Xw - y||^2 / n\nnp.random.seed(0)\nn, d = 1000, 20\nX = np.random.randn(n, d)\nw_true = np.random.randn(d)\ny = X @ w_true + 0.1 * np.random.randn(n)\n\nloss_fn = lambda w, X, y: np.mean((X @ w - y)**2)\ngrad_fn = lambda w, X, y: 2 * X.T @ (X @ w - y) / len(y)\n\n# Compare batch sizes\nfor bs in [1, 32, 256, n]:\n    w0 = np.zeros(d)\n    n_epochs = 20 if bs < n else 200\n    lr = 0.01\n    w_final, losses = minibatch_sgd(loss_fn, grad_fn, w0, X, y, lr, bs, n_epochs)\n    final_loss = loss_fn(w_final, X, y)\n    print(f\"B={bs:4d}: final_loss={final_loss:.4f}, w_error={np.linalg.norm(w_final - w_true):.4f}\")"}, {"type": "heading", "level": 2, "content": "Gradient Flow: The Continuous-Time Perspective"}, {"type": "text", "content": "The gradient flow ODE dθ/dt = −∇f(θ) is the continuous-time limit of gradient descent as η→0. Solutions θ(t) satisfy f(θ(t)) decreasing monotonically. For convex f, gradient flow converges as f(θ(t)) − f* ≤ ‖θ(0)−θ*‖²/(2t). For strongly convex: f(θ(t)) − f* ≤ e^{−2μt}(f(θ(0))−f*). Gradient descent with step η approximates gradient flow with t = ηT. The gradient flow perspective enables: (1) continuous convergence proofs that transfer cleanly to discrete updates; (2) analysis of momentum as a second-order ODE (heavy ball: θ'' + γθ' + ∇f(θ) = 0); (3) stochastic gradient flow (Langevin dynamics: dθ = −∇f·dt + √(2T)dW) as a principled model for SGD’s inherent noise in finite-batch training regimes."}, {"type": "heading", "level": 2, "content": "Implementation Pitfalls"}, {"type": "text", "content": "Learning rate too large: GD diverges when η > 2/L (the step exceeds the curvature bound and oscillates). Symptom: loss increases after a few steps or oscillates wildly. Fix: check L via power iteration on the Hessian, set η ≤ 1/L. Learning rate too small: convergence is guaranteed but glacially slow — especially problematic with high condition number κ, where O(κ) steps are needed per digit of precision. Symptom: loss decreases steadily but very slowly. Forgetting to shuffle data: cyclic gradient estimates can have systematic bias and slow convergence significantly. Diagnosis: compare cyclic vs shuffled on a simple problem. Not normalizing features: creates ill-conditioned loss landscape where κ ≈ (max feature scale/min feature scale)² — gradient descent zigzags rather than converging directly."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Set initial LR via the learning rate range test: increase LR from 1e-7 to 10 over 100 steps, plot loss vs LR, pick the LR just before the loss starts to increase. For convex problems with known L, set η = 1/L exactly. For neural networks, start at η = 1e-3 (Adam) or η = 0.1 (SGD with momentum). Use cosine annealing from η_max to η_min = η_max/100 over training. Monitor gradient norm ‖∇L‖: should decrease over training for convex objectives. Sudden spikes in gradient norm indicate instability — reduce LR or add gradient clipping. Feature normalization (zero mean, unit variance) is critical: it transforms the loss landscape from highly anisotropic to approximately isotropic, reducing the effective condition number and enabling larger safe learning rates."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport torch\n\ndef learning_rate_range_test(model, optimizer_cls, train_loader,\n                              start_lr=1e-7, end_lr=10.0, n_steps=100):\n    \"\"\"\n    LR range test (Smith 2015): increase LR geometrically, find sweet spot.\n    Returns lr_history, loss_history for plotting.\n    \"\"\"\n    # Build LR schedule: geometric increase\n    lr_schedule = np.geomspace(start_lr, end_lr, n_steps)\n    optimizer = optimizer_cls(model.parameters(), lr=start_lr)\n\n    lr_history = []\n    loss_history = []\n    smoothed_loss = None\n    beta = 0.9  # EMA smoothing\n\n    for step, (lr, batch) in enumerate(zip(lr_schedule, train_loader)):\n        # Update LR\n        for pg in optimizer.param_groups:\n            pg['lr'] = float(lr)\n\n        X, y = batch\n        optimizer.zero_grad()\n        loss = torch.nn.functional.mse_loss(model(X), y)\n        loss.backward()\n        optimizer.step()\n\n        raw = loss.item()\n        smoothed_loss = beta * (smoothed_loss or raw) + (1 - beta) * raw\n        lr_history.append(float(lr))\n        loss_history.append(smoothed_loss / (1 - beta**(step+1)))\n\n    # Find suggested LR: where loss starts increasing\n    best_idx = np.argmin(loss_history)\n    suggested_lr = lr_history[max(0, best_idx - 5)]  # slightly before minimum\n    print(f\"Suggested LR: {suggested_lr:.2e}\")\n    return lr_history, loss_history\n\nprint(\"LR range test function defined — call with model + dataloader\")\n# Example use: lr_hist, loss_hist = learning_rate_range_test(model, torch.optim.SGD, loader)"}, {"type": "callout", "title": "Learning Rate Is the Most Critical Hyperparameter", "content": "For convex L-smooth functions, eta > 2/L causes divergence — the loss will increase monotonically. For neural networks, the critical LR is harder to bound but the symptom is the same: loss spikes after 1-3 steps. Setting eta = 1/L (where L is approximately the max Hessian eigenvalue) guarantees descent but may be 10-100x too conservative. The practical sweet spot is identified via the LR range test or grid search. With cosine annealing, use eta_max from the range test and decay to eta_max/100."}, {"type": "table", "headers": ["Function Class", "GD Convergence Rate", "Steps to epsilon", "Optimal eta"], "rows": [["Non-smooth convex", "O(1/sqrt(T))", "O(1/epsilon^2)", "O(1/sqrt(T)) decreasing"], ["Smooth convex (L-smooth)", "O(1/T)", "O(1/epsilon)", "1/L"], ["Strongly convex + smooth", "O(rho^T), rho=(kappa-1)/(kappa+1)", "O(kappa log(1/epsilon))", "2/(mu+L)"], ["PL condition (non-convex)", "O(rho^T) linear", "O(log(1/epsilon))", "1/L"], ["Non-convex (general)", "||grad f(theta_T)||->0 (stationary)", "O(1/epsilon^2)", "1/L"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "items": ["GD update theta <- theta - eta*grad(f) is steepest descent; the negative gradient direction is the locally fastest path downhill by Cauchy-Schwarz.", "L-smoothness guarantees descent for eta <= 1/L. For convex functions: O(1/T) rate. For mu-strongly convex: linear rate O(rho^T) with rho=(kappa-1)/(kappa+1).", "Condition number kappa = L/mu controls convergence speed. High kappa means elongated loss landscape — GD zigzags. Momentum and Adam implicitly address this.", "Non-convex functions (neural networks) have saddle points where GD can stall. The Polyak-Lojasiewicz condition enables linear convergence without convexity.", "Mini-batch SGD with shuffling is the practical algorithm. Batch size B reduces variance by B but requires LR scaling (linear scaling rule).", "The gradient flow ODE d(theta)/dt = -grad(f)(theta) is the continuous limit; it enables cleaner convergence proofs that transfer to discrete GD via step-size discretization.", "Use the LR range test to find eta_max; apply cosine annealing from eta_max to eta_max/100 across training."]}]"
---

# Gradient Descent — Convergence Analysis and Step Size

Gradient descent is the backbone of virtually every machine learning optimizer. Yet most practitioners treat it as a black box: subtract the gradient, scale by learning rate, repeat. A rigorous understanding — convergence rates, smoothness conditions, saddle point dynamics, and the relationship between discrete updates and continuous gradient flow — is essential for choosing learning rates correctly, diagnosing training failures, and understanding why more sophisticated optimizers (Adam, Lion) help. This note covers: update rule derivation, L-smooth convergence guarantees, convex vs strongly convex rates, non-convex landscape difficulties, and the gradient flow ODE perspective.

## Core Definition: The Update Rule

The gradient descent update for minimizing f: ℝⁿ → ℝ is θₜ₊₁ = θₜ − η∇f(θₜ), where η > 0 is the learning rate (step size). The negative gradient direction −∇f(θ) is the steepest descent direction (by Cauchy-Schwarz: the direction maximally decreasing f per unit distance). Each step decreases f by approximately η‖∇f‖² (to first order): f(θₜ − η∇f) ≈ f(θ) − η‖∇f‖². The continuous analogue is the gradient flow ODE: dθ/dt = −∇f(θ), which converges to a stationary point as t→∞ under mild conditions. Discrete GD approximates this ODE with step size η as the temporal discretization parameter.

```python
import numpy as np
import matplotlib.pyplot as plt

def gradient_descent(grad_f, x0, lr, n_steps, f=None):
    """Basic gradient descent. Returns trajectory and loss history."""
    x = np.array(x0, dtype=np.float64)
    trajectory = [x.copy()]
    losses = [f(x)] if f else []

    for t in range(n_steps):
        g = grad_f(x)
        x = x - lr * g
        trajectory.append(x.copy())
        if f: losses.append(f(x))

    return np.array(trajectory), losses

# Example: minimize f(x, y) = x^2 + 4y^2 (condition number kappa = 4)
f = lambda x: x[0]**2 + 4*x[1]**2
grad_f = lambda x: np.array([2*x[0], 8*x[1]])

x0 = np.array([3.0, 2.0])

# Three learning rates: optimal eta = 1/L = 1/8, too small, too large
for lr, label in [(0.001, 'too small'), (0.125, 'optimal eta=1/L'), (0.26, 'too large')]:
    traj, losses = gradient_descent(grad_f, x0, lr=lr, n_steps=200, f=f)
    if losses:
        final = losses[-1]
        print(f"lr={lr} ({label}): final loss={final:.6f} after 200 steps")
    else:
        print(f"lr={lr} ({label}): diverged")

# Exact convergence rate for strongly convex: f(theta_T) - f* <= (1 - 2*eta*mu*L/(mu+L))^T * (f(theta_0) - f*)
# For f(x,y) = x^2 + 4y^2: mu = 2 (min eigenvalue of Hessian), L = 8 (max eigenvalue)
mu, L = 2.0, 8.0
eta_opt = 2 / (mu + L)  # Optimal step for strongly convex: 2/(mu+L)
rho = (L - mu) / (L + mu)  # Convergence rate
print(f"\nOptimal eta for strongly convex: {eta_opt:.4f}, rho = {rho:.4f}")
print(f"Steps to 1e-6 precision: {int(np.log(1e-6) / np.log(rho)) + 1}")
```

## L-Smoothness and Convergence Guarantees

A function f is L-smooth (L-Lipschitz gradient) if ‖∇f(x) − ∇f(y)‖ ≤ L‖x−y‖ for all x,y. Equivalently: f(y) ≤ f(x) + ∇f(x)ᵀ(y−x) + L/2‖y−x‖² (the gradient descent lemma). This quadratic upper bound guarantees that a step η = 1/L always decreases f: f(θ−η∇f) ≤ f(θ) − (1/2L)‖∇f(θ)‖². For convex L-smooth f: gradient descent with η ≤ 1/L achieves f(θₜ) − f* ≤ ‖θ₀−θ*‖²/(2ηT) — rate O(1/T). For μ-strongly convex L-smooth f: f(θₜ) − f* ≤ (1−2ημL/(μ+L))ᵀ(f(θ₀)−f*) — linear rate O(ρᵀ) where ρ = (κ−1)/(κ+1) < 1, κ = L/μ. Strong convexity provides the pull toward minimum that enables linear convergence.

```python
import numpy as np

def verify_l_smoothness(f, grad_f, x, y, L_candidate):
    """Check if L-smoothness inequality holds at x, y."""
    lhs = f(y)
    rhs = f(x) + grad_f(x) @ (y - x) + L_candidate/2 * np.linalg.norm(y-x)**2
    return lhs <= rhs + 1e-10, lhs, rhs

def convergence_rate_analysis(f, grad_f, x0, f_star, mu, L, n_steps=500):
    """
    Analyze convergence rate for L-smooth strongly convex function.
    Expected: linear rate rho = (L-mu)/(L+mu).
    """
    eta = 2.0 / (mu + L)  # Optimal step size for strongly convex
    x = x0.copy()
    gaps = []

    for t in range(n_steps):
        gap = f(x) - f_star
        gaps.append(gap)
        if gap < 1e-12: break
        x = x - eta * grad_f(x)

    # Fit empirical convergence rate
    rho_theory = (L - mu) / (L + mu)
    rho_empirical = (gaps[-1] / gaps[0]) ** (1 / len(gaps))

    return np.array(gaps), rho_theory, rho_empirical

# f(x) = x^T A x / 2  where A = diag(2, 4, 6, 8)  (strongly convex, L-smooth)
A = np.diag([2.0, 4.0, 6.0, 8.0])
f = lambda x: 0.5 * x @ A @ x
grad_f = lambda x: A @ x
x0 = np.array([3.0, 2.0, 1.0, 0.5])
f_star = 0.0  # minimum at origin
mu, L = 2.0, 8.0  # min and max eigenvalues of A

gaps, rho_th, rho_emp = convergence_rate_analysis(f, grad_f, x0, f_star, mu, L)
print(f"Theoretical rate rho = {rho_th:.4f}")
print(f"Empirical rate rho = {rho_emp:.4f}")
print(f"Steps to 1e-6: theoretical {int(np.log(1e-6) / np.log(rho_th))+1}, actual {len(gaps)}")

# Verify L-smoothness
x_test = np.array([1.0, 1.0, 1.0, 1.0])
y_test = x_test + 0.1 * np.random.randn(4)
ok, lhs, rhs = verify_l_smoothness(f, grad_f, x_test, y_test, L)
print(f"\nL-smoothness check: {ok}  (lhs={lhs:.4f} <= rhs={rhs:.4f})")
```

## Non-Convex Landscapes: Saddle Points and Local Minima

For non-convex f (all neural networks), GD is not guaranteed to find the global minimum. Two obstacles arise: (1) Local minima — GD converges to a local stationary point ∇f(θ*)=0. However, for over-parameterized networks, recent theory (e.g., NTK regime) suggests that local minima are often near-global. (2) Saddle points — critical points where some Hessian eigenvalues are negative (directions of decrease exist). In high dimensions, saddle points are exponentially more common than local minima (Bhojanapalli et al.). The Polyak-Łojasiewicz (PL) condition provides non-convex convergence: if ‖∇f‖² ≥ 2μ(f−f*), then GD converges linearly even without convexity. Over-parameterized neural networks often satisfy PL empirically, which helps explain why GD finds good solutions despite the non-convex landscape.

## ML Connections: Batch GD vs Mini-Batch vs SGD

Full-batch GD computes the gradient over the entire dataset. For n samples and d parameters: cost O(nd) per step. Mini-batch GD uses a random subset B of size B: gradient estimate ĝ = (1/B)Σ_{i∈B}∇Lᵢ(θ). This is an unbiased estimate of the true gradient: E[ĝ] = ∇L. Variance: Var[ĝ] ≈ σ²/B where σ² is the per-sample gradient variance. SGD (B=1) has highest variance but best parallelism and implicit regularization. Minibatch SGD with B=256–4096 is the practical sweet spot: enough noise for generalization, enough signal for stable convergence. The linear scaling rule (Goyal et al. 2017): multiply LR by B/256 when scaling batch size — this preserves gradient noise statistics and keeps the effective update magnitude constant across different hardware configurations.

```python
import numpy as np

def minibatch_sgd(loss_fn, grad_fn, theta0, X, y, lr, batch_size, n_epochs):
    """
    Minibatch SGD with data shuffling per epoch.
    Returns: final theta, per-epoch average loss.
    """
    theta = theta0.copy()
    n = len(X)
    epoch_losses = []

    for epoch in range(n_epochs):
        # Shuffle data each epoch (critical for convergence)
        idx = np.random.permutation(n)
        X_shuf, y_shuf = X[idx], y[idx]

        batch_losses = []
        for start in range(0, n, batch_size):
            end = min(start + batch_size, n)
            Xb = X_shuf[start:end]
            yb = y_shuf[start:end]

            g = grad_fn(theta, Xb, yb)
            theta = theta - lr * g
            batch_losses.append(loss_fn(theta, Xb, yb))

        epoch_losses.append(np.mean(batch_losses))

    return theta, epoch_losses

# Linear regression: L(w) = ||Xw - y||^2 / n
np.random.seed(0)
n, d = 1000, 20
X = np.random.randn(n, d)
w_true = np.random.randn(d)
y = X @ w_true + 0.1 * np.random.randn(n)

loss_fn = lambda w, X, y: np.mean((X @ w - y)**2)
grad_fn = lambda w, X, y: 2 * X.T @ (X @ w - y) / len(y)

# Compare batch sizes
for bs in [1, 32, 256, n]:
    w0 = np.zeros(d)
    n_epochs = 20 if bs < n else 200
    lr = 0.01
    w_final, losses = minibatch_sgd(loss_fn, grad_fn, w0, X, y, lr, bs, n_epochs)
    final_loss = loss_fn(w_final, X, y)
    print(f"B={bs:4d}: final_loss={final_loss:.4f}, w_error={np.linalg.norm(w_final - w_true):.4f}")
```

## Gradient Flow: The Continuous-Time Perspective

The gradient flow ODE dθ/dt = −∇f(θ) is the continuous-time limit of gradient descent as η→0. Solutions θ(t) satisfy f(θ(t)) decreasing monotonically. For convex f, gradient flow converges as f(θ(t)) − f* ≤ ‖θ(0)−θ*‖²/(2t). For strongly convex: f(θ(t)) − f* ≤ e^{−2μt}(f(θ(0))−f*). Gradient descent with step η approximates gradient flow with t = ηT. The gradient flow perspective enables: (1) continuous convergence proofs that transfer cleanly to discrete updates; (2) analysis of momentum as a second-order ODE (heavy ball: θ'' + γθ' + ∇f(θ) = 0); (3) stochastic gradient flow (Langevin dynamics: dθ = −∇f·dt + √(2T)dW) as a principled model for SGD’s inherent noise in finite-batch training regimes.

## Implementation Pitfalls

Learning rate too large: GD diverges when η > 2/L (the step exceeds the curvature bound and oscillates). Symptom: loss increases after a few steps or oscillates wildly. Fix: check L via power iteration on the Hessian, set η ≤ 1/L. Learning rate too small: convergence is guaranteed but glacially slow — especially problematic with high condition number κ, where O(κ) steps are needed per digit of precision. Symptom: loss decreases steadily but very slowly. Forgetting to shuffle data: cyclic gradient estimates can have systematic bias and slow convergence significantly. Diagnosis: compare cyclic vs shuffled on a simple problem. Not normalizing features: creates ill-conditioned loss landscape where κ ≈ (max feature scale/min feature scale)² — gradient descent zigzags rather than converging directly.

## Practical Guidance

Set initial LR via the learning rate range test: increase LR from 1e-7 to 10 over 100 steps, plot loss vs LR, pick the LR just before the loss starts to increase. For convex problems with known L, set η = 1/L exactly. For neural networks, start at η = 1e-3 (Adam) or η = 0.1 (SGD with momentum). Use cosine annealing from η_max to η_min = η_max/100 over training. Monitor gradient norm ‖∇L‖: should decrease over training for convex objectives. Sudden spikes in gradient norm indicate instability — reduce LR or add gradient clipping. Feature normalization (zero mean, unit variance) is critical: it transforms the loss landscape from highly anisotropic to approximately isotropic, reducing the effective condition number and enabling larger safe learning rates.

```python
import numpy as np
import torch

def learning_rate_range_test(model, optimizer_cls, train_loader,
                              start_lr=1e-7, end_lr=10.0, n_steps=100):
    """
    LR range test (Smith 2015): increase LR geometrically, find sweet spot.
    Returns lr_history, loss_history for plotting.
    """
    # Build LR schedule: geometric increase
    lr_schedule = np.geomspace(start_lr, end_lr, n_steps)
    optimizer = optimizer_cls(model.parameters(), lr=start_lr)

    lr_history = []
    loss_history = []
    smoothed_loss = None
    beta = 0.9  # EMA smoothing

    for step, (lr, batch) in enumerate(zip(lr_schedule, train_loader)):
        # Update LR
        for pg in optimizer.param_groups:
            pg['lr'] = float(lr)

        X, y = batch
        optimizer.zero_grad()
        loss = torch.nn.functional.mse_loss(model(X), y)
        loss.backward()
        optimizer.step()

        raw = loss.item()
        smoothed_loss = beta * (smoothed_loss or raw) + (1 - beta) * raw
        lr_history.append(float(lr))
        loss_history.append(smoothed_loss / (1 - beta**(step+1)))

    # Find suggested LR: where loss starts increasing
    best_idx = np.argmin(loss_history)
    suggested_lr = lr_history[max(0, best_idx - 5)]  # slightly before minimum
    print(f"Suggested LR: {suggested_lr:.2e}")
    return lr_history, loss_history

print("LR range test function defined — call with model + dataloader")
# Example use: lr_hist, loss_hist = learning_rate_range_test(model, torch.optim.SGD, loader)
```

> **Learning Rate Is the Most Critical Hyperparameter**: For convex L-smooth functions, eta > 2/L causes divergence — the loss will increase monotonically. For neural networks, the critical LR is harder to bound but the symptom is the same: loss spikes after 1-3 steps. Setting eta = 1/L (where L is approximately the max Hessian eigenvalue) guarantees descent but may be 10-100x too conservative. The practical sweet spot is identified via the LR range test or grid search. With cosine annealing, use eta_max from the range test and decay to eta_max/100.

| Function Class | GD Convergence Rate | Steps to epsilon | Optimal eta |
|---|---|---|---|
| Non-smooth convex | O(1/sqrt(T)) | O(1/epsilon^2) | O(1/sqrt(T)) decreasing |
| Smooth convex (L-smooth) | O(1/T) | O(1/epsilon) | 1/L |
| Strongly convex + smooth | O(rho^T), rho=(kappa-1)/(kappa+1) | O(kappa log(1/epsilon)) | 2/(mu+L) |
| PL condition (non-convex) | O(rho^T) linear | O(log(1/epsilon)) | 1/L |
| Non-convex (general) | ||grad f(theta_T)||->0 (stationary) | O(1/epsilon^2) | 1/L |

---

## Key Takeaways

- GD update theta <- theta - eta*grad(f) is steepest descent; the negative gradient direction is the locally fastest path downhill by Cauchy-Schwarz.
- L-smoothness guarantees descent for eta <= 1/L. For convex functions: O(1/T) rate. For mu-strongly convex: linear rate O(rho^T) with rho=(kappa-1)/(kappa+1).
- Condition number kappa = L/mu controls convergence speed. High kappa means elongated loss landscape — GD zigzags. Momentum and Adam implicitly address this.
- Non-convex functions (neural networks) have saddle points where GD can stall. The Polyak-Lojasiewicz condition enables linear convergence without convexity.
- Mini-batch SGD with shuffling is the practical algorithm. Batch size B reduces variance by B but requires LR scaling (linear scaling rule).
- The gradient flow ODE d(theta)/dt = -grad(f)(theta) is the continuous limit; it enables cleaner convergence proofs that transfer to discrete GD via step-size discretization.
- Use the LR range test to find eta_max; apply cosine annealing from eta_max to eta_max/100 across training.

