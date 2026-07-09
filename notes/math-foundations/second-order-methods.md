---
title: "Second-Order Methods — Newton and L-BFGS"
slug: "second-order-methods"
description: "Newton's method, quasi-Newton BFGS, L-BFGS with two-loop recursion, Wolfe line search, and when second-order methods beat first-order methods in practice."
tags: ["calculus", "optimization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"First-order methods (SGD, Adam) use only gradient information and treat all directions as equally important. Second-order methods incorporate curvature information via the Hessian, which rescales the gradient to account for different curvatures in different directions. The result: far fewer iterations to convergence, at the cost of computing, storing, or approximating the Hessian. For deep learning with billions of parameters the full Hessian is infeasible, but approximate second-order methods are an active research area."},{"type":"heading","level":2,"content":"Newton\u0027s Method"},{"type":"text","content":"Newton\u0027s update is x ← x − H⁻¹∇f(x) where H = ∇²f(x). This is derived from the second-order Taylor expansion: f(x+δ) ≈ f(x) + ∇f(x)ᵀδ + (1/2)δᵀHδ. Setting the gradient of this quadratic to zero gives δ = −H⁻¹∇f — the exact minimizer of the local quadratic approximation. For strictly convex quadratics Newton converges in exactly one step; for general smooth functions it achieves quadratic convergence near the minimum (the number of correct decimal digits roughly doubles each iteration)."},{"type":"callout","variant":"info","title":"Quadratic Convergence","content":"Newton\u0027s method converges quadratically: ‖x_{k+1} − x*‖ ≤ C·‖xₖ − x*‖². If the current error is ε, the next error is O(ε²). Starting from error 0.1: next steps are ~0.01, ~0.0001, ~10⁻⁸. This is exponentially faster than gradient descent\u0027s linear convergence ‖xₖ₊₁−x*‖ ≤ (1−μ/L)‖xₖ−x*‖. In practice Newton needs only 5–20 iterations where GD needs thousands."},{"type":"code","language":"python","content":"import numpy as np\n\ndef newtons_method(f, grad_f, hess_f, x0, tol=1e-10, max_iter=25):\n    \"\"\"Newton\u0027s method: x_{k+1} = x_k - H(x_k)^{-1} * grad_f(x_k).\"\"\"\n    x = x0.copy()\n    history = []\n    for k in range(max_iter):\n        g = grad_f(x)\n        H = hess_f(x)\n        step = np.linalg.solve(H, g)  # more stable than H^{-1} @ g\n        x = x - step\n        grad_norm = np.linalg.norm(grad_f(x))\n        history.append({\u0027iter\u0027: k+1, \u0027f\u0027: f(x), \u0027grad_norm\u0027: grad_norm})\n        if grad_norm \u003c tol:\n            break\n    return x, history\n\n# f(x,y) = 2x^2 + xy + 3y^2 - 4x - 6y  (strictly convex quadratic)\ndef f(v):      return 2*v[0]**2 + v[0]*v[1] + 3*v[1]**2 - 4*v[0] - 6*v[1]\ndef grad_f(v): return np.array([4*v[0]+v[1]-4, v[0]+6*v[1]-6])\ndef hess_f(v): return np.array([[4.0, 1.0], [1.0, 6.0]])\n\nx0 = np.array([4.0, 4.0])\nx_opt, hist = newtons_method(f, grad_f, hess_f, x0)\n\nprint(f\"Newton\u0027s method on 2D quadratic (start: {x0})\")\nprint(f\"{\u0027Iter\u0027:\u003c6} {\u0027f(x)\u0027:\u003e14} {\u0027||grad||\u0027:\u003e14}\")\nfor h in hist:\n    print(f\"{h[\u0027iter\u0027]:\u003c6} {h[\u0027f\u0027]:\u003e14.8f} {h[\u0027grad_norm\u0027]:\u003e14.2e}\")\nprint(f\"\\nOptimum: {x_opt}\")\nprint(\"Quadratic convergence: error squared each step.\")"},{"type":"heading","level":2,"content":"Why Newton Is Impractical for Deep Learning"},{"type":"text","content":"For a model with n parameters, the Hessian is an n×n matrix. With n=10⁸ (a medium-sized neural network), storing the Hessian requires 10¹⁶ bytes — vastly more than any GPU memory. Even computing Hessian-vector products (which avoid explicit storage) requires one backward pass per vector and you need O(n) such products for Lanczos. Inverting or factoring the Hessian is O(n³) — completely infeasible. These barriers motivate quasi-Newton methods that approximate H⁻¹ cheaply."},{"type":"list","ordered":false,"items":["Hessian storage: O(n²) — 10⁸ params → 10¹⁶ bytes (10 petabytes)","Hessian computation: O(n²) forward/backward passes in naive implementation","Hessian-vector product: O(n) via autodiff — one backward pass per vector","Hessian inversion: O(n³) — infeasible even for n=10⁴","Mini-batch gradients are noisy: second-order methods assume accurate gradient, break under noise","Non-convex landscapes: H may be indefinite (saddle), causing Newton to ascend"]},{"type":"heading","level":2,"content":"Quasi-Newton and the Secant Equation"},{"type":"text","content":"Quasi-Newton methods build up an approximation Bₖ ≈ H(xₖ) (or its inverse Hₖ ≈ H⁻¹) from gradient differences. The secant equation requires: Bₖ₊₁·sₖ = yₖ where sₖ = xₖ₊₁−xₖ (step) and yₖ = ∇f(xₖ₊₁)−∇f(xₖ) (gradient difference). This says the approximate Hessian should satisfy the first-order condition: the quadratic model matches the observed gradient change. BFGS applies a rank-2 update to the inverse Hessian that satisfies the secant equation and maintains positive definiteness."},{"type":"heading","level":2,"content":"L-BFGS: Limited Memory BFGS"},{"type":"text","content":"L-BFGS (Nocedal 1980) avoids storing the full n×n inverse Hessian approximation by keeping only the last m pairs {(sₖ, yₖ)} of step and gradient-difference vectors. The matrix-vector product Hₖ·q is computed implicitly using the two-loop recursion: it takes O(mn) time and O(mn) memory — dramatically better than O(n²). With m=10–20, L-BFGS achieves near-BFGS convergence on smooth objectives. It requires full-batch (or very large-batch) gradients; noisy mini-batch gradients cause the secant condition to be poorly satisfied."},{"type":"list","ordered":true,"items":["Store last m pairs: sₖ = xₖ₊₁−xₖ, yₖ = ∇f(xₖ₊₁)−∇f(xₖ)","Two-loop recursion: compute Hₖ·g without forming Hₖ explicitly in O(mn)","Direction: pₖ = −Hₖ·∇f(xₖ) (approximate Newton step)","Line search: find αₖ satisfying Wolfe conditions (sufficient decrease + curvature condition)","Update: xₖ₊₁ = xₖ + αₖ·pₖ; store new (s, y) pair; discard oldest if buffer full"]},{"type":"table","headers":["Method","Memory","Convergence Rate","Noisy Gradients","Typical Use"],"rows":[["Gradient Descent","O(n)","Linear: (1-μ/L)ᵏ","Robust (SGD)","Large-scale DL mini-batch"],["Newton","O(n²)","Quadratic near x*","Very sensitive","Tiny n, well-conditioned"],["BFGS","O(n²)","Superlinear","Sensitive","Medium n full-batch"],["L-BFGS","O(mn)","Superlinear (near BFGS)","Sensitive","Moderate n, full/large batch"],["Adam","O(n)","Adaptive, practical","Robust","Large-scale DL, mini-batch"],["K-FAC","O(n + layer²)","Near-quadratic (Fisher)","Moderate","DL with Kronecker approx"]]},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.optimize import minimize\nimport time\n\ndef rosenbrock(x):\n    return sum(100*(x[i+1]-x[i]**2)**2 + (1-x[i])**2 for i in range(len(x)-1))\n\ndef rosenbrock_grad(x):\n    g = np.zeros_like(x)\n    for i in range(len(x)-1):\n        g[i]   += -400*x[i]*(x[i+1]-x[i]**2) - 2*(1-x[i])\n        g[i+1] += 200*(x[i+1]-x[i]**2)\n    return g\n\nnp.random.seed(7)\nn = 40\nx0 = np.random.randn(n) * 0.5\n\nconfigs = [\n    (\u0027L-BFGS-B\u0027, dict(method=\u0027L-BFGS-B\u0027, jac=rosenbrock_grad,\n                      options={\u0027maxiter\u0027: 2000, \u0027ftol\u0027:1e-15, \u0027gtol\u0027:1e-10})),\n    (\u0027CG\u0027,       dict(method=\u0027CG\u0027, jac=rosenbrock_grad,\n                      options={\u0027maxiter\u0027: 5000, \u0027gtol\u0027:1e-10})),\n    (\u0027Nelder-Mead\u0027, dict(method=\u0027Nelder-Mead\u0027,\n                         options={\u0027maxiter\u0027: 50000, \u0027xatol\u0027:1e-8})),\n]\n\nprint(f\"Rosenbrock (n={n})  global min = 0.0\")\nprint(f\"{\u0027Method\u0027:\u003c14} {\u0027Final f\u0027:\u003e12} {\u0027Iters\u0027:\u003e8} {\u0027Time(s)\u0027:\u003e9}\")\nfor name, kwargs in configs:\n    t0 = time.time()\n    res = minimize(rosenbrock, x0.copy(), **kwargs)\n    print(f\"{name:\u003c14} {res.fun:\u003e12.2e} {res.nit:\u003e8} {time.time()-t0:\u003e9.3f}\")\nprint(\"\\nL-BFGS-B uses last m=10 gradient pairs; O(mn) memory vs O(n²) for full BFGS.\")"},{"type":"heading","level":2,"content":"L-BFGS in PyTorch"},{"type":"text","content":"PyTorch provides torch.optim.LBFGS which requires a closure — a callable that recomputes and returns the loss. This is necessary because L-BFGS performs internal line search with multiple function evaluations per step. The strong Wolfe line search (curvature condition) ensures the step satisfies the secant equation well, which is critical for building a good Hessian approximation."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass SmallNet(nn.Module):\n    def __init__(self, d_in=8, hidden=24, d_out=1):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(d_in, hidden), nn.Tanh(),\n            nn.Linear(hidden, hidden), nn.Tanh(),\n            nn.Linear(hidden, d_out)\n        )\n    def forward(self, x):\n        return self.net(x)\n\ntorch.manual_seed(0)\nmodel = SmallNet()\noptimizer = torch.optim.LBFGS(\n    model.parameters(),\n    lr=0.1,\n    max_iter=20,           # inner CG iterations per optimizer.step()\n    max_eval=25,           # max function evaluations per step\n    history_size=10,       # m: number of (s,y) pairs stored\n    line_search_fn=\u0027strong_wolfe\u0027\n)\n\nX = torch.randn(128, 8)\ny_true = torch.sin(X[:, :1]) + 0.1 * torch.randn(128, 1)\nloss_fn = nn.MSELoss()\n\ndef closure():\n    optimizer.zero_grad()\n    loss = loss_fn(model(X), y_true)\n    loss.backward()\n    return loss\n\nprint(\"L-BFGS training with strong Wolfe line search:\")\nlosses = []\nfor step in range(25):\n    loss = optimizer.step(closure)\n    losses.append(loss.item())\n    if step % 5 == 0:\n        print(f\"  Step {step:3d}: loss={loss.item():.6f}\")\nprint(f\"\\nFinal loss: {losses[-1]:.6f}\")\nprint(f\"Reduction: {losses[0]/losses[-1]:.1f}x in 25 steps\")"},{"type":"heading","level":2,"content":"Convergence Rate Comparison"},{"type":"text","content":"On quadratic problems, the convergence advantage of Newton over gradient descent is most clearly visible: Newton converges in a number of steps equal to the number of distinct eigenvalues of the Hessian (at most n steps for n×n H), while gradient descent needs O(κ·log(1/ε)) steps where κ=L/μ is the condition number. For ill-conditioned problems (large κ), gradient descent is orders of magnitude slower."},{"type":"code","language":"python","content":"import numpy as np\n\ndef make_quadratic(n=20, cond=200, seed=42):\n    \"\"\"Random convex quadratic with controlled condition number.\"\"\"\n    np.random.seed(seed)\n    eigvals = np.linspace(1, cond, n)\n    Q, _ = np.linalg.qr(np.random.randn(n, n))\n    A = Q @ np.diag(eigvals) @ Q.T\n    b = np.random.randn(n)\n    x_star = np.linalg.solve(A, b)\n    return A, b, x_star\n\ndef gd_errors(A, b, x_star, steps=300):\n    L = np.linalg.eigvalsh(A).max()\n    x, errors = np.zeros_like(b), []\n    for _ in range(steps):\n        x = x - (1.0/L) * (A @ x - b)\n        errors.append(np.linalg.norm(x - x_star))\n    return errors\n\ndef newton_errors(A, b, x_star, steps=15):\n    A_inv = np.linalg.inv(A)\n    x, errors = np.zeros_like(b), []\n    for _ in range(steps):\n        x = x - A_inv @ (A @ x - b)\n        errors.append(np.linalg.norm(x - x_star))\n    return errors\n\nA, b, x_star = make_quadratic(n=20, cond=200)\ngd_err = gd_errors(A, b, x_star)\nnewton_err = newton_errors(A, b, x_star)\n\ndef steps_to(errors, tol=1e-6):\n    for i, e in enumerate(errors):\n        if e \u003c tol: return i\n    return len(errors)\n\nprint(f\"Convergence on quadratic (n=20, condition number=200)\")\nprint(f\"{\u0027Method\u0027:\u003c10} {\u0027Steps to 1e-6\u0027:\u003e15} {\u0027Steps to 1e-10\u0027:\u003e15}\")\nprint(f\"{\u0027GD\u0027:\u003c10} {steps_to(gd_err,1e-6):\u003e15} {steps_to(gd_err,1e-10):\u003e15}\")\nprint(f\"{\u0027Newton\u0027:\u003c10} {steps_to(newton_err,1e-6):\u003e15} {steps_to(newton_err,1e-10):\u003e15}\")\nprint(\"\\nGD every 50 steps:\")\nfor i in range(0, 200, 50):\n    print(f\"  Step {i:3d}: {gd_err[i]:.2e}\")\nprint(\"Newton every step:\")\nfor i, e in enumerate(newton_err[:8]):\n    print(f\"  Step {i:3d}: {e:.2e}\")"},{"type":"callout","variant":"tip","title":"When to Use L-BFGS vs Adam","content":"L-BFGS is the right choice when: (1) you can afford full-batch gradients (small/medium dataset), (2) the objective is smooth and the Hessian is well-conditioned, (3) you need high-precision solutions (physics simulations, scientific computing). Adam is better when: (1) mini-batch gradients are required (large datasets), (2) the landscape is highly non-convex (deep networks), (3) training must be robust to gradient noise. Many practitioners use Adam for DL pretraining and L-BFGS for fine-tuning or small sub-problems."},{"type":"heading","level":2,"content":"Approximate Second-Order Methods for Deep Learning"},{"type":"text","content":"Several methods approximate curvature in deep networks at tractable cost. K-FAC (Kronecker-Factored Approximate Curvature) approximates the Fisher information matrix as a Kronecker product of smaller matrices — one per layer. This brings the per-layer cost to O(d_in² + d_out²) instead of O((d_in·d_out)²). Shampoo similarly uses Kronecker structure with gradient second-moment matrices. Sophia (second-order clipped stochastic optimization) clips the Hessian diagonal to prevent large steps in sharp directions."},{"type":"list","ordered":false,"items":["K-FAC: Fisher approximated as Kronecker product of input covariance and output gradient covariance","Shampoo: full-matrix AdaGrad with Kronecker factor preconditioning, O(d³/m) per step","Gauss-Newton: approximates Hessian as JᵀJ for least-squares problems — always PSD","Sophia: clips per-parameter Hessian diagonal estimate to bound step size — stable for LLMs","Adam as approximate second-order: diagonal Hessian approximation via gradient second moments"]},{"type":"divider"}]"
---
# Second-Order Methods — Newton and L-BFGS

First-order methods (SGD, Adam) use only gradient information and treat all directions as equally important. Second-order methods incorporate curvature information via the Hessian, which rescales the gradient to account for different curvatures in different directions. The result: far fewer iterations to convergence, at the cost of computing, storing, or approximating the Hessian. For deep learning with billions of parameters the full Hessian is infeasible, but approximate second-order methods are an active research area.

## Newton's Method

Newton's update is x ← x − H⁻¹∇f(x) where H = ∇²f(x). This is derived from the second-order Taylor expansion: f(x+δ) ≈ f(x) + ∇f(x)ᵀδ + (1/2)δᵀHδ. Setting the gradient of this quadratic to zero gives δ = −H⁻¹∇f — the exact minimizer of the local quadratic approximation. For strictly convex quadratics Newton converges in exactly one step; for general smooth functions it achieves quadratic convergence near the minimum (the number of correct decimal digits roughly doubles each iteration).

> **Quadratic Convergence**: Newton's method converges quadratically: ‖x_{k+1} − x*‖ ≤ C·‖xₖ − x*‖². If the current error is ε, the next error is O(ε²). Starting from error 0.1: next steps are ~0.01, ~0.0001, ~10⁻⁸. This is exponentially faster than gradient descent's linear convergence ‖xₖ₊₁−x*‖ ≤ (1−μ/L)‖xₖ−x*‖. In practice Newton needs only 5–20 iterations where GD needs thousands.

```python
import numpy as np

def newtons_method(f, grad_f, hess_f, x0, tol=1e-10, max_iter=25):
    """Newton's method: x_{k+1} = x_k - H(x_k)^{-1} * grad_f(x_k)."""
    x = x0.copy()
    history = []
    for k in range(max_iter):
        g = grad_f(x)
        H = hess_f(x)
        step = np.linalg.solve(H, g)  # more stable than H^{-1} @ g
        x = x - step
        grad_norm = np.linalg.norm(grad_f(x))
        history.append({'iter': k+1, 'f': f(x), 'grad_norm': grad_norm})
        if grad_norm < tol:
            break
    return x, history

# f(x,y) = 2x^2 + xy + 3y^2 - 4x - 6y  (strictly convex quadratic)
def f(v):      return 2*v[0]**2 + v[0]*v[1] + 3*v[1]**2 - 4*v[0] - 6*v[1]
def grad_f(v): return np.array([4*v[0]+v[1]-4, v[0]+6*v[1]-6])
def hess_f(v): return np.array([[4.0, 1.0], [1.0, 6.0]])

x0 = np.array([4.0, 4.0])
x_opt, hist = newtons_method(f, grad_f, hess_f, x0)

print(f"Newton's method on 2D quadratic (start: {x0})")
print(f"{'Iter':<6} {'f(x)':>14} {'||grad||':>14}")
for h in hist:
    print(f"{h['iter']:<6} {h['f']:>14.8f} {h['grad_norm']:>14.2e}")
print(f"\nOptimum: {x_opt}")
print("Quadratic convergence: error squared each step.")
```

## Why Newton Is Impractical for Deep Learning

For a model with n parameters, the Hessian is an n×n matrix. With n=10⁸ (a medium-sized neural network), storing the Hessian requires 10¹⁶ bytes — vastly more than any GPU memory. Even computing Hessian-vector products (which avoid explicit storage) requires one backward pass per vector and you need O(n) such products for Lanczos. Inverting or factoring the Hessian is O(n³) — completely infeasible. These barriers motivate quasi-Newton methods that approximate H⁻¹ cheaply.

- Hessian storage: O(n²) — 10⁸ params → 10¹⁶ bytes (10 petabytes)
- Hessian computation: O(n²) forward/backward passes in naive implementation
- Hessian-vector product: O(n) via autodiff — one backward pass per vector
- Hessian inversion: O(n³) — infeasible even for n=10⁴
- Mini-batch gradients are noisy: second-order methods assume accurate gradient, break under noise
- Non-convex landscapes: H may be indefinite (saddle), causing Newton to ascend

## Quasi-Newton and the Secant Equation

Quasi-Newton methods build up an approximation Bₖ ≈ H(xₖ) (or its inverse Hₖ ≈ H⁻¹) from gradient differences. The secant equation requires: Bₖ₊₁·sₖ = yₖ where sₖ = xₖ₊₁−xₖ (step) and yₖ = ∇f(xₖ₊₁)−∇f(xₖ) (gradient difference). This says the approximate Hessian should satisfy the first-order condition: the quadratic model matches the observed gradient change. BFGS applies a rank-2 update to the inverse Hessian that satisfies the secant equation and maintains positive definiteness.

## L-BFGS: Limited Memory BFGS

L-BFGS (Nocedal 1980) avoids storing the full n×n inverse Hessian approximation by keeping only the last m pairs {(sₖ, yₖ)} of step and gradient-difference vectors. The matrix-vector product Hₖ·q is computed implicitly using the two-loop recursion: it takes O(mn) time and O(mn) memory — dramatically better than O(n²). With m=10–20, L-BFGS achieves near-BFGS convergence on smooth objectives. It requires full-batch (or very large-batch) gradients; noisy mini-batch gradients cause the secant condition to be poorly satisfied.

1. Store last m pairs: sₖ = xₖ₊₁−xₖ, yₖ = ∇f(xₖ₊₁)−∇f(xₖ)
2. Two-loop recursion: compute Hₖ·g without forming Hₖ explicitly in O(mn)
3. Direction: pₖ = −Hₖ·∇f(xₖ) (approximate Newton step)
4. Line search: find αₖ satisfying Wolfe conditions (sufficient decrease + curvature condition)
5. Update: xₖ₊₁ = xₖ + αₖ·pₖ; store new (s, y) pair; discard oldest if buffer full

| Method | Memory | Convergence Rate | Noisy Gradients | Typical Use |
| --- | --- | --- | --- | --- |
| Gradient Descent | O(n) | Linear: (1-μ/L)ᵏ | Robust (SGD) | Large-scale DL mini-batch |
| Newton | O(n²) | Quadratic near x* | Very sensitive | Tiny n, well-conditioned |
| BFGS | O(n²) | Superlinear | Sensitive | Medium n full-batch |
| L-BFGS | O(mn) | Superlinear (near BFGS) | Sensitive | Moderate n, full/large batch |
| Adam | O(n) | Adaptive, practical | Robust | Large-scale DL, mini-batch |
| K-FAC | O(n + layer²) | Near-quadratic (Fisher) | Moderate | DL with Kronecker approx |

```python
import numpy as np
from scipy.optimize import minimize
import time

def rosenbrock(x):
    return sum(100*(x[i+1]-x[i]**2)**2 + (1-x[i])**2 for i in range(len(x)-1))

def rosenbrock_grad(x):
    g = np.zeros_like(x)
    for i in range(len(x)-1):
        g[i]   += -400*x[i]*(x[i+1]-x[i]**2) - 2*(1-x[i])
        g[i+1] += 200*(x[i+1]-x[i]**2)
    return g

np.random.seed(7)
n = 40
x0 = np.random.randn(n) * 0.5

configs = [
    ('L-BFGS-B', dict(method='L-BFGS-B', jac=rosenbrock_grad,
                      options={'maxiter': 2000, 'ftol':1e-15, 'gtol':1e-10})),
    ('CG',       dict(method='CG', jac=rosenbrock_grad,
                      options={'maxiter': 5000, 'gtol':1e-10})),
    ('Nelder-Mead', dict(method='Nelder-Mead',
                         options={'maxiter': 50000, 'xatol':1e-8})),
]

print(f"Rosenbrock (n={n})  global min = 0.0")
print(f"{'Method':<14} {'Final f':>12} {'Iters':>8} {'Time(s)':>9}")
for name, kwargs in configs:
    t0 = time.time()
    res = minimize(rosenbrock, x0.copy(), **kwargs)
    print(f"{name:<14} {res.fun:>12.2e} {res.nit:>8} {time.time()-t0:>9.3f}")
print("\nL-BFGS-B uses last m=10 gradient pairs; O(mn) memory vs O(n²) for full BFGS.")
```

## L-BFGS in PyTorch

PyTorch provides torch.optim.LBFGS which requires a closure — a callable that recomputes and returns the loss. This is necessary because L-BFGS performs internal line search with multiple function evaluations per step. The strong Wolfe line search (curvature condition) ensures the step satisfies the secant equation well, which is critical for building a good Hessian approximation.

```python
import torch
import torch.nn as nn

class SmallNet(nn.Module):
    def __init__(self, d_in=8, hidden=24, d_out=1):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(d_in, hidden), nn.Tanh(),
            nn.Linear(hidden, hidden), nn.Tanh(),
            nn.Linear(hidden, d_out)
        )
    def forward(self, x):
        return self.net(x)

torch.manual_seed(0)
model = SmallNet()
optimizer = torch.optim.LBFGS(
    model.parameters(),
    lr=0.1,
    max_iter=20,           # inner CG iterations per optimizer.step()
    max_eval=25,           # max function evaluations per step
    history_size=10,       # m: number of (s,y) pairs stored
    line_search_fn='strong_wolfe'
)

X = torch.randn(128, 8)
y_true = torch.sin(X[:, :1]) + 0.1 * torch.randn(128, 1)
loss_fn = nn.MSELoss()

def closure():
    optimizer.zero_grad()
    loss = loss_fn(model(X), y_true)
    loss.backward()
    return loss

print("L-BFGS training with strong Wolfe line search:")
losses = []
for step in range(25):
    loss = optimizer.step(closure)
    losses.append(loss.item())
    if step % 5 == 0:
        print(f"  Step {step:3d}: loss={loss.item():.6f}")
print(f"\nFinal loss: {losses[-1]:.6f}")
print(f"Reduction: {losses[0]/losses[-1]:.1f}x in 25 steps")
```

## Convergence Rate Comparison

On quadratic problems, the convergence advantage of Newton over gradient descent is most clearly visible: Newton converges in a number of steps equal to the number of distinct eigenvalues of the Hessian (at most n steps for n×n H), while gradient descent needs O(κ·log(1/ε)) steps where κ=L/μ is the condition number. For ill-conditioned problems (large κ), gradient descent is orders of magnitude slower.

```python
import numpy as np

def make_quadratic(n=20, cond=200, seed=42):
    """Random convex quadratic with controlled condition number."""
    np.random.seed(seed)
    eigvals = np.linspace(1, cond, n)
    Q, _ = np.linalg.qr(np.random.randn(n, n))
    A = Q @ np.diag(eigvals) @ Q.T
    b = np.random.randn(n)
    x_star = np.linalg.solve(A, b)
    return A, b, x_star

def gd_errors(A, b, x_star, steps=300):
    L = np.linalg.eigvalsh(A).max()
    x, errors = np.zeros_like(b), []
    for _ in range(steps):
        x = x - (1.0/L) * (A @ x - b)
        errors.append(np.linalg.norm(x - x_star))
    return errors

def newton_errors(A, b, x_star, steps=15):
    A_inv = np.linalg.inv(A)
    x, errors = np.zeros_like(b), []
    for _ in range(steps):
        x = x - A_inv @ (A @ x - b)
        errors.append(np.linalg.norm(x - x_star))
    return errors

A, b, x_star = make_quadratic(n=20, cond=200)
gd_err = gd_errors(A, b, x_star)
newton_err = newton_errors(A, b, x_star)

def steps_to(errors, tol=1e-6):
    for i, e in enumerate(errors):
        if e < tol: return i
    return len(errors)

print(f"Convergence on quadratic (n=20, condition number=200)")
print(f"{'Method':<10} {'Steps to 1e-6':>15} {'Steps to 1e-10':>15}")
print(f"{'GD':<10} {steps_to(gd_err,1e-6):>15} {steps_to(gd_err,1e-10):>15}")
print(f"{'Newton':<10} {steps_to(newton_err,1e-6):>15} {steps_to(newton_err,1e-10):>15}")
print("\nGD every 50 steps:")
for i in range(0, 200, 50):
    print(f"  Step {i:3d}: {gd_err[i]:.2e}")
print("Newton every step:")
for i, e in enumerate(newton_err[:8]):
    print(f"  Step {i:3d}: {e:.2e}")
```

> **When to Use L-BFGS vs Adam**: L-BFGS is the right choice when: (1) you can afford full-batch gradients (small/medium dataset), (2) the objective is smooth and the Hessian is well-conditioned, (3) you need high-precision solutions (physics simulations, scientific computing). Adam is better when: (1) mini-batch gradients are required (large datasets), (2) the landscape is highly non-convex (deep networks), (3) training must be robust to gradient noise. Many practitioners use Adam for DL pretraining and L-BFGS for fine-tuning or small sub-problems.

## Approximate Second-Order Methods for Deep Learning

Several methods approximate curvature in deep networks at tractable cost. K-FAC (Kronecker-Factored Approximate Curvature) approximates the Fisher information matrix as a Kronecker product of smaller matrices — one per layer. This brings the per-layer cost to O(d_in² + d_out²) instead of O((d_in·d_out)²). Shampoo similarly uses Kronecker structure with gradient second-moment matrices. Sophia (second-order clipped stochastic optimization) clips the Hessian diagonal to prevent large steps in sharp directions.

- K-FAC: Fisher approximated as Kronecker product of input covariance and output gradient covariance
- Shampoo: full-matrix AdaGrad with Kronecker factor preconditioning, O(d³/m) per step
- Gauss-Newton: approximates Hessian as JᵀJ for least-squares problems — always PSD
- Sophia: clips per-parameter Hessian diagonal estimate to bound step size — stable for LLMs
- Adam as approximate second-order: diagonal Hessian approximation via gradient second moments

---

