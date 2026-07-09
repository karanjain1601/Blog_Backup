---
title: "Nesterov Accelerated Gradient (NAG)"
slug: "nesterov-momentum"
description: "Derivation of Nesterov accelerated gradient from the lookahead correction, convergence rate analysis achieving O(1/T²), the variable substitution implementation trick, and connection to Adam's Nesterov variant."
tags: ["optimization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Nesterov Accelerated Gradient is the theoretically optimal first-order method for convex smooth optimization, achieving the O(1/T²) convergence rate that matches information-theoretic lower bounds for this function class. The key insight — evaluate the gradient at the anticipated future position (θ − βv) rather than the current position θ — produces a correction that dramatically reduces overshoot and achieves optimal convergence. Beyond its theoretical elegance, NAG is practically important: PyTorch's SGD with nesterov=True uses it; the Nesterov-style momentum correction also appears in Adam-based variants like Nadam. Understanding NAG's convergence proof (via potential functions and energy arguments) reveals why the specific update order matters and why the lookahead gradient provides strictly more information than the current-position gradient."}, {"type": "heading", "level": 2, "content": "Core Definition: The Lookahead Correction"}, {"type": "text", "content": "Heavy ball (classical momentum): vₜ = βvₜ₋₁ + ηg(θₜ); θₜ₊₁ = θₜ − vₜ. Nesterov's correction: evaluate the gradient at the anticipated position θₜ − βvₜ₋₁ (where we will land after applying the current velocity) rather than at θₜ itself. Update: vₜ = βvₜ₋₁ + η∇f(θₜ − βvₜ₋₁); θₜ₊₁ = θₜ − vₜ. The lookahead position θₜ − βvₜ₋₁ is a first-order prediction of where θₜ₊₁ would land with the current velocity alone. Evaluating the gradient there instead of at θₜ provides a correction that accounts for momentum: if the gradient at the lookahead position opposes the velocity, NAG brakes early, preventing overshoot. This lookahead correction is why NAG achieves O(1/T²) for general convex functions, while heavy ball only achieves O(1/T²) for quadratics specifically."}, {"type": "code", "language": "python", "content": "import numpy as np\n\ndef nesterov_ag(grad_f, theta0, lr, beta, n_steps, f=None):\n    \"\"\"\n    Nesterov Accelerated Gradient.\n    Evaluates gradient at look-ahead position: theta - beta * v.\n    \"\"\"\n    theta = np.array(theta0, dtype=np.float64)\n    v = np.zeros_like(theta)\n    losses = [f(theta)] if f else []\n\n    for t in range(n_steps):\n        # Key difference from heavy ball: gradient at lookahead position\n        lookahead = theta - beta * v\n        g = grad_f(lookahead)\n        v = beta * v + lr * g\n        theta = theta - v\n        if f: losses.append(f(theta))\n\n    return losses\n\ndef heavy_ball(grad_f, theta0, lr, beta, n_steps, f=None):\n    \"\"\"Classical momentum (heavy ball): gradient at current position.\"\"\"\n    theta = np.array(theta0, dtype=np.float64)\n    v = np.zeros_like(theta)\n    losses = [f(theta)] if f else []\n\n    for t in range(n_steps):\n        g = grad_f(theta)  # gradient at current position (not lookahead)\n        v = beta * v + lr * g\n        theta = theta - v\n        if f: losses.append(f(theta))\n\n    return losses\n\n# Compare on ill-conditioned quadratic: f(x,y) = 0.5*(x^2 + 100*y^2)\nf = lambda x: 0.5 * (x[0]**2 + 100*x[1]**2)\ngrad_f = lambda x: np.array([x[0], 100*x[1]])\nx0 = np.array([10.0, 1.0])\n\nL, mu = 100.0, 1.0\nbeta_opt = (np.sqrt(L) - np.sqrt(mu)) / (np.sqrt(L) + np.sqrt(mu))\nlr_opt = (1 / (np.sqrt(L) + np.sqrt(mu)))**2 * 4  # approx optimal for NAG\n\nlosses_nag = nesterov_ag(grad_f, x0, lr=lr_opt, beta=beta_opt, n_steps=200, f=f)\nlosses_hb = heavy_ball(grad_f, x0, lr=lr_opt, beta=beta_opt, n_steps=200, f=f)\n\ndef steps_to(losses, threshold=1e-4):\n    return next((i for i, l in enumerate(losses) if l < threshold), len(losses))\n\nprint(f\"beta_opt = {beta_opt:.4f}\")\nprint(f\"NAG: {steps_to(losses_nag)} steps to 1e-4\")\nprint(f\"Heavy ball: {steps_to(losses_hb)} steps to 1e-4\")"}, {"type": "heading", "level": 2, "content": "Variable Substitution: The Efficient Implementation"}, {"type": "text", "content": "Naively implementing NAG requires computing the gradient at two points per step (θₜ and θₜ − βvₜ₋₁). The variable substitution φₜ = θₜ − βvₜ₋₁ (define the lookahead position as a new variable) eliminates this overhead. In terms of φₜ, after algebraic manipulation of the original update equations, the update simplifies to: φₜ₊₁ = φₜ + β(φₜ − φₜ₋₁) − η∇f(φₜ). In this form, the gradient is always evaluated at φₜ (the current point), and the momentum term is the displacement φₜ − φₜ₋₁ from the previous step. This requires only one gradient evaluation per step — the same cost as vanilla GD or heavy ball. PyTorch's SGD with nesterov=True uses this equivalent single-variable form internally, storing a momentum buffer buf and computing the Nesterov-corrected gradient as g + β·buf."}, {"type": "code", "language": "python", "content": "import numpy as np\n\ndef nesterov_single_variable(grad_f, phi0, lr, beta, n_steps, f=None):\n    \"\"\"\n    NAG using the phi-variable substitution.\n    phi_{t+1} = phi_t + beta*(phi_t - phi_{t-1}) - eta*grad(f)(phi_t)\n    Only ONE gradient evaluation per step (at current phi).\n    Mathematically equivalent to the lookahead formulation.\n    \"\"\"\n    phi = np.array(phi0, dtype=np.float64)\n    phi_prev = phi.copy()\n    losses = [f(phi)] if f else []\n\n    for t in range(n_steps):\n        g = grad_f(phi)\n        phi_new = phi + beta * (phi - phi_prev) - lr * g\n        phi_prev = phi\n        phi = phi_new\n        if f: losses.append(f(phi))\n\n    return losses\n\ndef nesterov_pytorch_style(grad_f, theta0, lr, beta, n_steps, f=None):\n    \"\"\"\n    PyTorch's SGD nesterov=True implementation.\n    Stores buf (momentum buffer) and updates with Nesterov correction.\n    \"\"\"\n    theta = np.array(theta0, dtype=np.float64)\n    buf = np.zeros_like(theta)\n    losses = [f(theta)] if f else []\n\n    for t in range(n_steps):\n        g = grad_f(theta)\n        buf = beta * buf + g                    # momentum buffer\n        # Nesterov: add beta * buf to gradient before stepping\n        g_nesterov = g + beta * buf\n        theta = theta - lr * g_nesterov\n        if f: losses.append(f(theta))\n\n    return losses\n\n# Verify both formulations give same convergence\nf = lambda x: 0.5 * (x[0]**2 + 100*x[1]**2)\ngrad_f = lambda x: np.array([x[0], 100*x[1]])\nx0 = np.array([10.0, 1.0])\n\nlosses_sv = nesterov_single_variable(grad_f, x0.copy(), lr=0.002, beta=0.81, n_steps=200, f=f)\nlosses_pt = nesterov_pytorch_style(grad_f, x0.copy(), lr=0.002, beta=0.81, n_steps=200, f=f)\n\nprint(f\"Single-variable NAG:  final loss = {losses_sv[-1]:.6f}\")\nprint(f\"PyTorch-style NAG:    final loss = {losses_pt[-1]:.6f}\")\nprint(f\"Both formulations match: {abs(losses_sv[-1] - losses_pt[-1]) < 1e-6}\")"}, {"type": "heading", "level": 2, "content": "Convergence Rate: O(1/T²) for Convex Smooth Functions"}, {"type": "text", "content": "Nesterov's convergence theorem: for L-smooth convex f, NAG achieves f(θₜ)−f* ≤ 2L‖θ₀−θ*‖²/(t+1)² = O(1/T²). This is a factor of T improvement over GD's O(1/T). The proof uses a potential (Lyapunov) function Eₜ = t²(f(θₜ)−f*) + (1/2)‖...‖² that decreases monotonically along the iterates. The specific choice of momentum sequence βₜ (not necessarily constant) is derived from the convergence proof: βₜ = (1−aₜ)/aₜ₊₁ where aₜ = (1+√(1+4a²ₜ₋₁))/2, with this sequence satisfying aₜ ≈ t/2 asymptotically. For strongly convex problems: NAG achieves linear rate O((1−√(μ/L))ᵀ) — ρ = 1−1/√κ vs ρ = 1−1/κ for GD. NAG needs O(√κ) iterations vs O(κ) for GD, a square-root improvement in the condition-number dependence that is critical for highly ill-conditioned problems."}, {"type": "heading", "level": 2, "content": "ML Connections"}, {"type": "text", "content": "Nesterov momentum is used across multiple ML frameworks: (1) torch.optim.SGD with nesterov=True is the default for many image classification training recipes including ResNet on ImageNet; (2) Adam variants like Nadam (Dozat 2016) incorporate the Nesterov correction into Adam's update: instead of using the exponential moving average mₜ as the update direction, Nadam uses a bias-corrected estimate of the next gradient mₜ₊₁, providing a lookahead correction within the adaptive learning rate framework. (3) In meta-learning (MAML): the inner loop uses GD for task adaptation, but the outer loop update differentiates through the inner loop and can use NAG for faster convergence of the meta-objective across tasks. (4) L-BFGS uses a quasi-Newton direction that incorporates gradient history in a manner analogous to momentum, but with a second-order approximation of the curvature."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn as nn\n\ndef compare_sgd_variants(n_steps=500):\n    \"\"\"\n    Compare SGD, SGD+Momentum, and SGD+Nesterov on a simple regression task.\n    \"\"\"\n    torch.manual_seed(42)\n\n    # Synthetic regression: 50 features, ill-conditioned\n    X = torch.randn(200, 50)\n    # Create ill-conditioning by scaling features\n    scale = torch.logspace(0, 2, 50)  # features scaled 1x to 100x\n    X = X * scale.unsqueeze(0)\n    w_true = torch.randn(50)\n    y = X @ w_true + 0.1 * torch.randn(200)\n\n    def make_model():\n        return nn.Linear(50, 1, bias=False)\n\n    def run(opt_name, optimizer):\n        model = make_model()\n        criterion = nn.MSELoss()\n        losses = []\n        for step in range(n_steps):\n            optimizer.zero_grad()\n            loss = criterion(model(X).squeeze(), y)\n            loss.backward()\n            optimizer.step()\n            losses.append(loss.item())\n        return losses\n\n    model_gd = make_model()\n    model_mom = make_model()\n    model_nag = make_model()\n\n    losses_gd = run('GD', torch.optim.SGD(model_gd.parameters(), lr=0.001))\n    losses_mom = run('Mom', torch.optim.SGD(model_mom.parameters(), lr=0.001, momentum=0.9))\n    losses_nag = run('NAG', torch.optim.SGD(model_nag.parameters(), lr=0.001, momentum=0.9, nesterov=True))\n\n    for name, losses in [('GD', losses_gd), ('Momentum', losses_mom), ('Nesterov', losses_nag)]:\n        final = losses[-1]\n        steps_1pct = next((i for i, l in enumerate(losses) if l < losses[0]*0.01), n_steps)\n        print(f\"{name:10}: final_loss={final:.4f}, steps to 1% of initial: {steps_1pct}\")\n\ncompare_sgd_variants()"}, {"type": "heading", "level": 2, "content": "NAG vs Classical Momentum: Geometric Intuition"}, {"type": "text", "content": "The geometric difference between the two methods is subtle but consequential. Heavy ball computes the gradient at the current position θₜ, then applies the gradient to update the velocity, and finally moves. The momentum carries the optimizer to a new position θₜ₊₁. If the gradient at θₜ₊₁ would be zero (we are at the minimum), heavy ball still overshoots because the velocity term carries it past. NAG computes the gradient at the anticipated position θₜ − βvₜ₋₁, receiving early warning about the gradient in the direction of travel. If the gradient at the lookahead is decelerating (opposing the velocity), NAG reduces the step before overshooting, while heavy ball only reacts at the next step. This correction is especially important near the minimum where the loss function is strongly curved and the cost of overshoot compounds across many iterations."}, {"type": "heading", "level": 2, "content": "Implementation Pitfalls"}, {"type": "text", "content": "The most common NAG pitfall: confusing the lookahead formulation with the single-variable formulation and implementing neither correctly. PyTorch's SGD with nesterov=True uses the buf formulation: computes buf = β·buf + g, then updates θ with the Nesterov-corrected gradient g + β·buf. This is mathematically equivalent to the lookahead form but requires only one gradient evaluation. Common pitfall: using nesterov=True without momentum (β=0) simply recovers vanilla GD — Nesterov requires β > 0 to provide any benefit. Second pitfall: applying gradient clipping incorrectly with NAG. Clip the Nesterov-corrected gradient g_nesterov = g + β·buf, not the raw gradient g alone, to maintain the correct effective update magnitude. Clipping only the raw gradient underestimates the true update size by a factor of approximately 1/(1−β)."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Use nesterov=True whenever using SGD with momentum — it is strictly better in theory and empirically matches or exceeds heavy ball on most tasks at zero additional computational cost. Standard recipe for image classification: SGD with momentum=0.9, nesterov=True, LR starting at 0.1 with cosine decay over 90-200 epochs, weight decay 1e-4. For Adam-based training where Nesterov correction is desired, use Nadam (available in TensorFlow natively; in PyTorch implement via the explicit Nesterov-corrected Adam update rule). Monitor convergence: NAG should reach lower loss in fewer steps than heavy ball on the same LR and beta settings for convex or nearly-convex problems. If heavy ball outperforms NAG, the loss landscape is strongly non-convex and the theoretical guarantees for NAG do not apply directly to the current problem."}, {"type": "code", "language": "python", "content": "import torch\nimport numpy as np\n\ndef nesterov_convergence_rate_plot(n_steps=300):\n    \"\"\"Empirically verify O(1/T^2) vs O(1/T) convergence rates.\"\"\"\n\n    # Pure quadratic: f(theta) = 0.5 * theta^T * A * theta\n    # L = 10, mu = 1 (condition number 10)\n    A = torch.diag(torch.tensor([1.0, 2.0, 4.0, 6.0, 8.0, 10.0]))\n    f = lambda theta: 0.5 * theta @ A @ theta\n    grad_f = lambda theta: A @ theta\n\n    theta0 = torch.ones(6) * 5.0\n    L, mu = 10.0, 1.0\n    eta_gd = 1.0 / L\n    eta_nag = 1.0 / L\n    beta_nag = (np.sqrt(L) - np.sqrt(mu)) / (np.sqrt(L) + np.sqrt(mu))\n\n    # Run GD and NAG\n    theta_gd = theta0.clone()\n    phi_prev = theta0.clone()\n    phi = theta0.clone()\n\n    losses_gd, losses_nag = [], []\n    for t in range(n_steps):\n        losses_gd.append(f(theta_gd).item())\n        losses_nag.append(f(phi).item())\n\n        theta_gd = theta_gd - eta_gd * grad_f(theta_gd)\n        phi_new = phi + beta_nag * (phi - phi_prev) - eta_nag * grad_f(phi)\n        phi_prev, phi = phi, phi_new\n\n    # Check rates: GD should follow 1/T, NAG should follow 1/T^2\n    t = np.arange(1, n_steps + 1, dtype=float)\n    corr_gd = np.corrcoef(np.log(t), np.log(np.maximum(losses_gd, 1e-12)))[0, 1]\n    corr_nag = np.corrcoef(np.log(t**2), np.log(np.maximum(losses_nag, 1e-12)))[0, 1]\n    print(f\"GD log-log correlation with 1/T:   {corr_gd:.3f} (expect ~-1 for O(1/T))\")\n    print(f\"NAG log-log correlation with 1/T^2: {corr_nag:.3f} (expect ~-1 for O(1/T^2))\")\n\nnesterov_convergence_rate_plot()"}, {"type": "callout", "title": "NAG Guarantees Apply Only to Convex Functions", "content": "Nesterov's O(1/T^2) convergence theorem requires convexity. For non-convex functions (neural networks), NAG has no theoretical guarantee over heavy ball — both converge to stationary points at O(1/T) rate in terms of ||grad(f)||^2. In practice, Nesterov often performs similarly to or slightly better than heavy ball for neural networks, which is why PyTorch includes nesterov=True as an option. But if you see heavy ball outperforming NAG on a specific task, this is consistent with theory — NAG's advantage is provably restricted to the convex case."}, {"type": "table", "headers": ["Method", "Gradient Eval", "Convex Rate", "Strongly Convex Rate", "PyTorch"], "rows": [["GD", "at theta_t", "O(1/T)", "O((1-mu/L)^T)", "SGD(momentum=0)"], ["Heavy ball", "at theta_t", "O(1/T^2) quadratic only", "O((1-sqrt(mu/L))^T) quadratic", "SGD(momentum=beta)"], ["Nesterov (NAG)", "at theta_t - beta*v_{t-1}", "O(1/T^2) general", "O((1-sqrt(mu/L))^T)", "SGD(momentum=beta, nesterov=True)"], ["Nadam", "at phi_t (Adam+NAG)", "N/A (adaptive)", "N/A", "Not in PyTorch natively"], ["L-BFGS", "at theta_t (line search)", "Superlinear", "Quadratic", "LBFGS optimizer"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "items": ["NAG evaluates gradient at the lookahead position theta_t - beta*v_{t-1}, giving early warning about the gradient at the destination and preventing overshoot.", "Convergence: NAG achieves O(1/T^2) for convex smooth functions vs O(1/T) for GD. For strongly convex: O(exp(-T*sqrt(mu/L))) vs O(exp(-T*mu/L)) — square-root improvement in condition number dependence.", "The single-variable form phi_{t+1} = phi_t + beta*(phi_t - phi_{t-1}) - eta*grad(f)(phi_t) requires only one gradient evaluation per step.", "PyTorch implements NAG as: buf = beta*buf + g, then step with g + beta*buf (Nesterov-corrected gradient). This is equivalent to the lookahead formulation.", "For non-convex neural networks, NAG offers no theoretical guarantee over heavy ball but often matches or slightly exceeds it empirically.", "Always use nesterov=True when using SGD with momentum in PyTorch — it is strictly better for convex objectives and costs nothing extra.", "Clip gradients using the Nesterov-corrected gradient g + beta*buf, not the raw gradient g, to maintain correct update magnitude."]}]"
---

# Nesterov Accelerated Gradient (NAG)

Nesterov Accelerated Gradient is the theoretically optimal first-order method for convex smooth optimization, achieving the O(1/T²) convergence rate that matches information-theoretic lower bounds for this function class. The key insight — evaluate the gradient at the anticipated future position (θ − βv) rather than the current position θ — produces a correction that dramatically reduces overshoot and achieves optimal convergence. Beyond its theoretical elegance, NAG is practically important: PyTorch's SGD with nesterov=True uses it; the Nesterov-style momentum correction also appears in Adam-based variants like Nadam. Understanding NAG's convergence proof (via potential functions and energy arguments) reveals why the specific update order matters and why the lookahead gradient provides strictly more information than the current-position gradient.

## Core Definition: The Lookahead Correction

Heavy ball (classical momentum): vₜ = βvₜ₋₁ + ηg(θₜ); θₜ₊₁ = θₜ − vₜ. Nesterov's correction: evaluate the gradient at the anticipated position θₜ − βvₜ₋₁ (where we will land after applying the current velocity) rather than at θₜ itself. Update: vₜ = βvₜ₋₁ + η∇f(θₜ − βvₜ₋₁); θₜ₊₁ = θₜ − vₜ. The lookahead position θₜ − βvₜ₋₁ is a first-order prediction of where θₜ₊₁ would land with the current velocity alone. Evaluating the gradient there instead of at θₜ provides a correction that accounts for momentum: if the gradient at the lookahead position opposes the velocity, NAG brakes early, preventing overshoot. This lookahead correction is why NAG achieves O(1/T²) for general convex functions, while heavy ball only achieves O(1/T²) for quadratics specifically.

```python
import numpy as np

def nesterov_ag(grad_f, theta0, lr, beta, n_steps, f=None):
    """
    Nesterov Accelerated Gradient.
    Evaluates gradient at look-ahead position: theta - beta * v.
    """
    theta = np.array(theta0, dtype=np.float64)
    v = np.zeros_like(theta)
    losses = [f(theta)] if f else []

    for t in range(n_steps):
        # Key difference from heavy ball: gradient at lookahead position
        lookahead = theta - beta * v
        g = grad_f(lookahead)
        v = beta * v + lr * g
        theta = theta - v
        if f: losses.append(f(theta))

    return losses

def heavy_ball(grad_f, theta0, lr, beta, n_steps, f=None):
    """Classical momentum (heavy ball): gradient at current position."""
    theta = np.array(theta0, dtype=np.float64)
    v = np.zeros_like(theta)
    losses = [f(theta)] if f else []

    for t in range(n_steps):
        g = grad_f(theta)  # gradient at current position (not lookahead)
        v = beta * v + lr * g
        theta = theta - v
        if f: losses.append(f(theta))

    return losses

# Compare on ill-conditioned quadratic: f(x,y) = 0.5*(x^2 + 100*y^2)
f = lambda x: 0.5 * (x[0]**2 + 100*x[1]**2)
grad_f = lambda x: np.array([x[0], 100*x[1]])
x0 = np.array([10.0, 1.0])

L, mu = 100.0, 1.0
beta_opt = (np.sqrt(L) - np.sqrt(mu)) / (np.sqrt(L) + np.sqrt(mu))
lr_opt = (1 / (np.sqrt(L) + np.sqrt(mu)))**2 * 4  # approx optimal for NAG

losses_nag = nesterov_ag(grad_f, x0, lr=lr_opt, beta=beta_opt, n_steps=200, f=f)
losses_hb = heavy_ball(grad_f, x0, lr=lr_opt, beta=beta_opt, n_steps=200, f=f)

def steps_to(losses, threshold=1e-4):
    return next((i for i, l in enumerate(losses) if l < threshold), len(losses))

print(f"beta_opt = {beta_opt:.4f}")
print(f"NAG: {steps_to(losses_nag)} steps to 1e-4")
print(f"Heavy ball: {steps_to(losses_hb)} steps to 1e-4")
```

## Variable Substitution: The Efficient Implementation

Naively implementing NAG requires computing the gradient at two points per step (θₜ and θₜ − βvₜ₋₁). The variable substitution φₜ = θₜ − βvₜ₋₁ (define the lookahead position as a new variable) eliminates this overhead. In terms of φₜ, after algebraic manipulation of the original update equations, the update simplifies to: φₜ₊₁ = φₜ + β(φₜ − φₜ₋₁) − η∇f(φₜ). In this form, the gradient is always evaluated at φₜ (the current point), and the momentum term is the displacement φₜ − φₜ₋₁ from the previous step. This requires only one gradient evaluation per step — the same cost as vanilla GD or heavy ball. PyTorch's SGD with nesterov=True uses this equivalent single-variable form internally, storing a momentum buffer buf and computing the Nesterov-corrected gradient as g + β·buf.

```python
import numpy as np

def nesterov_single_variable(grad_f, phi0, lr, beta, n_steps, f=None):
    """
    NAG using the phi-variable substitution.
    phi_{t+1} = phi_t + beta*(phi_t - phi_{t-1}) - eta*grad(f)(phi_t)
    Only ONE gradient evaluation per step (at current phi).
    Mathematically equivalent to the lookahead formulation.
    """
    phi = np.array(phi0, dtype=np.float64)
    phi_prev = phi.copy()
    losses = [f(phi)] if f else []

    for t in range(n_steps):
        g = grad_f(phi)
        phi_new = phi + beta * (phi - phi_prev) - lr * g
        phi_prev = phi
        phi = phi_new
        if f: losses.append(f(phi))

    return losses

def nesterov_pytorch_style(grad_f, theta0, lr, beta, n_steps, f=None):
    """
    PyTorch's SGD nesterov=True implementation.
    Stores buf (momentum buffer) and updates with Nesterov correction.
    """
    theta = np.array(theta0, dtype=np.float64)
    buf = np.zeros_like(theta)
    losses = [f(theta)] if f else []

    for t in range(n_steps):
        g = grad_f(theta)
        buf = beta * buf + g                    # momentum buffer
        # Nesterov: add beta * buf to gradient before stepping
        g_nesterov = g + beta * buf
        theta = theta - lr * g_nesterov
        if f: losses.append(f(theta))

    return losses

# Verify both formulations give same convergence
f = lambda x: 0.5 * (x[0]**2 + 100*x[1]**2)
grad_f = lambda x: np.array([x[0], 100*x[1]])
x0 = np.array([10.0, 1.0])

losses_sv = nesterov_single_variable(grad_f, x0.copy(), lr=0.002, beta=0.81, n_steps=200, f=f)
losses_pt = nesterov_pytorch_style(grad_f, x0.copy(), lr=0.002, beta=0.81, n_steps=200, f=f)

print(f"Single-variable NAG:  final loss = {losses_sv[-1]:.6f}")
print(f"PyTorch-style NAG:    final loss = {losses_pt[-1]:.6f}")
print(f"Both formulations match: {abs(losses_sv[-1] - losses_pt[-1]) < 1e-6}")
```

## Convergence Rate: O(1/T²) for Convex Smooth Functions

Nesterov's convergence theorem: for L-smooth convex f, NAG achieves f(θₜ)−f* ≤ 2L‖θ₀−θ*‖²/(t+1)² = O(1/T²). This is a factor of T improvement over GD's O(1/T). The proof uses a potential (Lyapunov) function Eₜ = t²(f(θₜ)−f*) + (1/2)‖...‖² that decreases monotonically along the iterates. The specific choice of momentum sequence βₜ (not necessarily constant) is derived from the convergence proof: βₜ = (1−aₜ)/aₜ₊₁ where aₜ = (1+√(1+4a²ₜ₋₁))/2, with this sequence satisfying aₜ ≈ t/2 asymptotically. For strongly convex problems: NAG achieves linear rate O((1−√(μ/L))ᵀ) — ρ = 1−1/√κ vs ρ = 1−1/κ for GD. NAG needs O(√κ) iterations vs O(κ) for GD, a square-root improvement in the condition-number dependence that is critical for highly ill-conditioned problems.

## ML Connections

Nesterov momentum is used across multiple ML frameworks: (1) torch.optim.SGD with nesterov=True is the default for many image classification training recipes including ResNet on ImageNet; (2) Adam variants like Nadam (Dozat 2016) incorporate the Nesterov correction into Adam's update: instead of using the exponential moving average mₜ as the update direction, Nadam uses a bias-corrected estimate of the next gradient mₜ₊₁, providing a lookahead correction within the adaptive learning rate framework. (3) In meta-learning (MAML): the inner loop uses GD for task adaptation, but the outer loop update differentiates through the inner loop and can use NAG for faster convergence of the meta-objective across tasks. (4) L-BFGS uses a quasi-Newton direction that incorporates gradient history in a manner analogous to momentum, but with a second-order approximation of the curvature.

```python
import torch
import torch.nn as nn

def compare_sgd_variants(n_steps=500):
    """
    Compare SGD, SGD+Momentum, and SGD+Nesterov on a simple regression task.
    """
    torch.manual_seed(42)

    # Synthetic regression: 50 features, ill-conditioned
    X = torch.randn(200, 50)
    # Create ill-conditioning by scaling features
    scale = torch.logspace(0, 2, 50)  # features scaled 1x to 100x
    X = X * scale.unsqueeze(0)
    w_true = torch.randn(50)
    y = X @ w_true + 0.1 * torch.randn(200)

    def make_model():
        return nn.Linear(50, 1, bias=False)

    def run(opt_name, optimizer):
        model = make_model()
        criterion = nn.MSELoss()
        losses = []
        for step in range(n_steps):
            optimizer.zero_grad()
            loss = criterion(model(X).squeeze(), y)
            loss.backward()
            optimizer.step()
            losses.append(loss.item())
        return losses

    model_gd = make_model()
    model_mom = make_model()
    model_nag = make_model()

    losses_gd = run('GD', torch.optim.SGD(model_gd.parameters(), lr=0.001))
    losses_mom = run('Mom', torch.optim.SGD(model_mom.parameters(), lr=0.001, momentum=0.9))
    losses_nag = run('NAG', torch.optim.SGD(model_nag.parameters(), lr=0.001, momentum=0.9, nesterov=True))

    for name, losses in [('GD', losses_gd), ('Momentum', losses_mom), ('Nesterov', losses_nag)]:
        final = losses[-1]
        steps_1pct = next((i for i, l in enumerate(losses) if l < losses[0]*0.01), n_steps)
        print(f"{name:10}: final_loss={final:.4f}, steps to 1% of initial: {steps_1pct}")

compare_sgd_variants()
```

## NAG vs Classical Momentum: Geometric Intuition

The geometric difference between the two methods is subtle but consequential. Heavy ball computes the gradient at the current position θₜ, then applies the gradient to update the velocity, and finally moves. The momentum carries the optimizer to a new position θₜ₊₁. If the gradient at θₜ₊₁ would be zero (we are at the minimum), heavy ball still overshoots because the velocity term carries it past. NAG computes the gradient at the anticipated position θₜ − βvₜ₋₁, receiving early warning about the gradient in the direction of travel. If the gradient at the lookahead is decelerating (opposing the velocity), NAG reduces the step before overshooting, while heavy ball only reacts at the next step. This correction is especially important near the minimum where the loss function is strongly curved and the cost of overshoot compounds across many iterations.

## Implementation Pitfalls

The most common NAG pitfall: confusing the lookahead formulation with the single-variable formulation and implementing neither correctly. PyTorch's SGD with nesterov=True uses the buf formulation: computes buf = β·buf + g, then updates θ with the Nesterov-corrected gradient g + β·buf. This is mathematically equivalent to the lookahead form but requires only one gradient evaluation. Common pitfall: using nesterov=True without momentum (β=0) simply recovers vanilla GD — Nesterov requires β > 0 to provide any benefit. Second pitfall: applying gradient clipping incorrectly with NAG. Clip the Nesterov-corrected gradient g_nesterov = g + β·buf, not the raw gradient g alone, to maintain the correct effective update magnitude. Clipping only the raw gradient underestimates the true update size by a factor of approximately 1/(1−β).

## Practical Guidance

Use nesterov=True whenever using SGD with momentum — it is strictly better in theory and empirically matches or exceeds heavy ball on most tasks at zero additional computational cost. Standard recipe for image classification: SGD with momentum=0.9, nesterov=True, LR starting at 0.1 with cosine decay over 90-200 epochs, weight decay 1e-4. For Adam-based training where Nesterov correction is desired, use Nadam (available in TensorFlow natively; in PyTorch implement via the explicit Nesterov-corrected Adam update rule). Monitor convergence: NAG should reach lower loss in fewer steps than heavy ball on the same LR and beta settings for convex or nearly-convex problems. If heavy ball outperforms NAG, the loss landscape is strongly non-convex and the theoretical guarantees for NAG do not apply directly to the current problem.

```python
import torch
import numpy as np

def nesterov_convergence_rate_plot(n_steps=300):
    """Empirically verify O(1/T^2) vs O(1/T) convergence rates."""

    # Pure quadratic: f(theta) = 0.5 * theta^T * A * theta
    # L = 10, mu = 1 (condition number 10)
    A = torch.diag(torch.tensor([1.0, 2.0, 4.0, 6.0, 8.0, 10.0]))
    f = lambda theta: 0.5 * theta @ A @ theta
    grad_f = lambda theta: A @ theta

    theta0 = torch.ones(6) * 5.0
    L, mu = 10.0, 1.0
    eta_gd = 1.0 / L
    eta_nag = 1.0 / L
    beta_nag = (np.sqrt(L) - np.sqrt(mu)) / (np.sqrt(L) + np.sqrt(mu))

    # Run GD and NAG
    theta_gd = theta0.clone()
    phi_prev = theta0.clone()
    phi = theta0.clone()

    losses_gd, losses_nag = [], []
    for t in range(n_steps):
        losses_gd.append(f(theta_gd).item())
        losses_nag.append(f(phi).item())

        theta_gd = theta_gd - eta_gd * grad_f(theta_gd)
        phi_new = phi + beta_nag * (phi - phi_prev) - eta_nag * grad_f(phi)
        phi_prev, phi = phi, phi_new

    # Check rates: GD should follow 1/T, NAG should follow 1/T^2
    t = np.arange(1, n_steps + 1, dtype=float)
    corr_gd = np.corrcoef(np.log(t), np.log(np.maximum(losses_gd, 1e-12)))[0, 1]
    corr_nag = np.corrcoef(np.log(t**2), np.log(np.maximum(losses_nag, 1e-12)))[0, 1]
    print(f"GD log-log correlation with 1/T:   {corr_gd:.3f} (expect ~-1 for O(1/T))")
    print(f"NAG log-log correlation with 1/T^2: {corr_nag:.3f} (expect ~-1 for O(1/T^2))")

nesterov_convergence_rate_plot()
```

> **NAG Guarantees Apply Only to Convex Functions**: Nesterov's O(1/T^2) convergence theorem requires convexity. For non-convex functions (neural networks), NAG has no theoretical guarantee over heavy ball — both converge to stationary points at O(1/T) rate in terms of ||grad(f)||^2. In practice, Nesterov often performs similarly to or slightly better than heavy ball for neural networks, which is why PyTorch includes nesterov=True as an option. But if you see heavy ball outperforming NAG on a specific task, this is consistent with theory — NAG's advantage is provably restricted to the convex case.

| Method | Gradient Eval | Convex Rate | Strongly Convex Rate | PyTorch |
|---|---|---|---|---|
| GD | at theta_t | O(1/T) | O((1-mu/L)^T) | SGD(momentum=0) |
| Heavy ball | at theta_t | O(1/T^2) quadratic only | O((1-sqrt(mu/L))^T) quadratic | SGD(momentum=beta) |
| Nesterov (NAG) | at theta_t - beta*v_{t-1} | O(1/T^2) general | O((1-sqrt(mu/L))^T) | SGD(momentum=beta, nesterov=True) |
| Nadam | at phi_t (Adam+NAG) | N/A (adaptive) | N/A | Not in PyTorch natively |
| L-BFGS | at theta_t (line search) | Superlinear | Quadratic | LBFGS optimizer |

---

## Key Takeaways

- NAG evaluates gradient at the lookahead position theta_t - beta*v_{t-1}, giving early warning about the gradient at the destination and preventing overshoot.
- Convergence: NAG achieves O(1/T^2) for convex smooth functions vs O(1/T) for GD. For strongly convex: O(exp(-T*sqrt(mu/L))) vs O(exp(-T*mu/L)) — square-root improvement in condition number dependence.
- The single-variable form phi_{t+1} = phi_t + beta*(phi_t - phi_{t-1}) - eta*grad(f)(phi_t) requires only one gradient evaluation per step.
- PyTorch implements NAG as: buf = beta*buf + g, then step with g + beta*buf (Nesterov-corrected gradient). This is equivalent to the lookahead formulation.
- For non-convex neural networks, NAG offers no theoretical guarantee over heavy ball but often matches or slightly exceeds it empirically.
- Always use nesterov=True when using SGD with momentum in PyTorch — it is strictly better for convex objectives and costs nothing extra.
- Clip gradients using the Nesterov-corrected gradient g + beta*buf, not the raw gradient g, to maintain correct update magnitude.

