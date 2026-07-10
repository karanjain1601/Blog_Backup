---
title: "Neural ODEs — Continuous-Depth Models"
slug: "neural-odes"
description: "Neural ODEs (Chen et al. 2018) replace discrete layers with a continuous ODE dx/dt = f(x,t,theta) solved by Runge-Kutta. The adjoint method backpropagates through the solver in O(1) memory. FFJORD uses Hutchinson's trace estimator for scalable continuous normalizing flows."
tags: ["deep-learning", "generative-models", "diffusion-models", "normalizing-flows"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Neural ODEs (Chen et al., 2018) define a model where the hidden state evolves continuously: dx/dt = f(x, t, θ). The output is x(T) = x(0) + ⌠⌡ f(x(t), t, θ) dt, computed by an ODE solver. Instead of a fixed number of discrete layers, the solver adaptively chooses how many function evaluations to use. This gives continuous-time dynamics, O(1) memory backpropagation via the adjoint method, and a natural framework for continuous normalizing flows where the log-determinant evolves via the trace of the Jacobian."},{"type":"heading","level":2,"content":"From Discrete Layers to Continuous Dynamics"},{"type":"text","content":"A residual network computes x_{l+1} = x_l + f(x_l, θ_l). As the step size Δt → 0 and the number of layers → ∞ with Δt fixed, this converges to the ODE dx/dt = f(x, t, θ). Neural ODE parameterizes f with a neural network and uses an ODE solver (Euler, RK4, or adaptive Dopri5) to integrate from t=0 to t=T. The solver evaluates f multiple times per step; the total number of evaluations is the effective depth, chosen adaptively based on error tolerance."},{"type":"heading","level":2,"content":"ODE Solvers and Adaptive Computation"},{"type":"text","content":"The Dormand-Prince (Dopri5) solver is a 4(5)th-order Runge-Kutta method with adaptive step size. It estimates the local truncation error by comparing 4th and 5th order solutions; if the error exceeds the tolerance, the step is rejected and retried with a smaller step. This means the solver uses more evaluations in regions where f changes rapidly and fewer where dynamics are smooth. The number of function evaluations is not fixed: it depends on the input, making Neural ODEs irregular compute models."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n# Install: pip install torchdiffeq\nfrom torchdiffeq import odeint\n\nclass ODEFunc(nn.Module):\n    \"\"\"Dynamics: dx/dt = f(x, t, theta). Network takes (x, t_encoded) as input.\"\"\"\n    def __init__(self, d):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(d + 1, 64), nn.Tanh(),\n            nn.Linear(64, 64),   nn.Tanh(),\n            nn.Linear(64, d))\n\n    def forward(self, t, x):\n        t_vec = t.expand(x.shape[0], 1)\n        return self.net(torch.cat([x, t_vec], dim=1))\n\nclass NeuralODE(nn.Module):\n    def __init__(self, d, t_span=(0., 1.), method=\u0027dopri5\u0027):\n        super().__init__()\n        self.func   = ODEFunc(d)\n        self.t      = torch.tensor(t_span)\n        self.method = method\n\n    def forward(self, x0):\n        # odeint returns shape (time_points, batch, d)\n        traj = odeint(self.func, x0, self.t, method=self.method)\n        return traj[-1]   # final state x(T)\n\ntorch.manual_seed(0)\nmodel = NeuralODE(d=4)\nx0 = torch.randn(32, 4)\nx_T = model(x0)\nprint(f\"Input: {x0.shape} -\u003e Output: {x_T.shape}\")\nprint(\"Dopri5 adaptively chooses step size; effective depth is input-dependent\")"},{"type":"heading","level":2,"content":"Adjoint Sensitivity Method"},{"type":"text","content":"Standard autograd stores all intermediate activations from the ODE solver, requiring O(N_steps) memory. The adjoint method avoids this: define the adjoint a(t) = dL/dx(t). It satisfies its own ODE da/dt = -a(t) × (∂f/∂x), solved backward from t=T to t=0. Gradients with respect to θ are obtained by integrating a(t) × (∂f/∂θ) along this trajectory. The backward ODE requires only one ODE solve (no stored activations), giving O(1) memory regardless of solver steps. The trade-off: approximately 2× the compute of the forward pass."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n# torchdiffeq provides adjoint-based backprop\nfrom torchdiffeq import odeint_adjoint\n\nclass AdjointNeuralODE(nn.Module):\n    \"\"\"\n    Uses adjoint sensitivity method:\n    - Forward: solve ODE from t=0 to T (standard).\n    - Backward: solve adjoint ODE from T to 0 — no stored intermediates.\n    - Memory: O(1) regardless of number of solver steps.\n    \"\"\"\n    def __init__(self, d):\n        super().__init__()\n        self.func = ODEFunc(d)\n        self.t    = torch.tensor([0., 1.])\n\n    def forward(self, x0):\n        return odeint_adjoint(\n            self.func, x0, self.t,\n            method=\u0027dopri5\u0027,\n            adjoint_params=list(self.func.parameters())\n        )[-1]\n\ndef count_params(m): return sum(p.numel() for p in m.parameters())\n\ntorch.manual_seed(42)\nd, B = 8, 64\nnode = AdjointNeuralODE(d)\nx0 = torch.randn(B, d, requires_grad=True)\nx_T = node(x0)\nloss = x_T.sum()\nloss.backward()\n\nprint(f\"Parameters: {count_params(node)}\")\nprint(f\"x0 gradient shape: {x0.grad.shape}\")\nprint(\"Adjoint: backward pass solves another ODE -- O(1) memory, ~2x compute\")\nprint(\"Standard autograd: O(N_steps) memory -- infeasible for tight tolerances\")"},{"type":"heading","level":2,"content":"Continuous Normalizing Flows (FFJORD)"},{"type":"text","content":"A Continuous Normalizing Flow (CNF) models the change in log-density as dx evolves: d log p(x) / dt = -Tr(∂f/∂x). Computing the exact trace requires d backward passes (one per output dimension), costing O(d²) per step. FFJORD (Grathwohl et al., 2019) uses Hutchinson\u0027s estimator: Tr(J) ≈ E[eᵀ J e] for e ~ N(0,I) or Rademacher. One sample suffices during training, reducing trace cost to O(d) per ODE step. FFJORD achieves competitive log-likelihood with fewer parameters than discrete flows."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass CNFDynamics(nn.Module):\n    \"\"\"\n    CNF joint dynamics: d(z, log_pz)/dt = (f(z,t), -Tr(df/dz)).\n    Hutchinson estimator: Tr(J) ~ e^T (J e) for e ~ Rademacher.\n    Reduces O(d^2) exact trace to O(d) per step.\n    \"\"\"\n    def __init__(self, d, hidden=64):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(d + 1, hidden), nn.Tanh(),\n            nn.Linear(hidden, hidden), nn.Tanh(),\n            nn.Linear(hidden, d))\n\n    def forward(self, t, state):\n        z, log_pz = state\n        t_vec = t.expand(z.shape[0], 1)\n        z_in  = torch.cat([z, t_vec], dim=-1).requires_grad_(True)\n        f = self.net(z_in)\n        # Hutchinson trace estimator\n        e = (torch.randint_like(z, 0, 2).float() * 2 - 1)  # Rademacher\n        e_Jf = torch.autograd.grad(f, z_in, e, create_graph=True)[0][..., :z.shape[-1]]\n        trace_est = (e * e_Jf).sum(dim=-1, keepdim=True)\n        return f, -trace_est\n\ndef hutchinson_trace_check(d=16, n_est=100):\n    \"\"\"Verify Hutchinson estimator converges to exact trace.\"\"\"\n    J = torch.randn(d, d)\n    exact_trace = J.trace().item()\n    estimates = [(torch.randn(d) @ J @ torch.randn(d)).item() for _ in range(n_est)]\n    print(f\"Exact trace: {exact_trace:.4f}\")\n    print(f\"Hutchinson mean ({n_est} samples): {sum(estimates)/n_est:.4f}\")\n    print(\"Tr(J) = E[e^T J e] is unbiased for any e with E[ee^T]=I\")\n\nhutchinson_trace_check()"},{"type":"heading","level":2,"content":"Neural ODE vs ResNet"},{"type":"text","content":"Both ResNets and Neural ODEs compute a sequence of transformations, but ResNets fix the number of function evaluations at graph construction time while Neural ODEs adapt to input complexity. A Neural ODE with tolerance 1e-5 may use 10-100 function evaluations where a 6-block ResNet uses exactly 6. For simple inputs, the ODE solver may need fewer evaluations than the ResNet; for complex inputs, more. This makes Neural ODEs more expressive per parameter but slower and less predictable in wall-clock time."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\n\nclass ResNet(nn.Module):\n    def __init__(self, d, n_blocks):\n        super().__init__()\n        self.blocks = nn.ModuleList([\n            nn.Sequential(nn.Linear(d, d), nn.Tanh(), nn.Linear(d, d))\n            for _ in range(n_blocks)])\n    def forward(self, x):\n        for blk in self.blocks:\n            x = x + blk(x)\n        return x\n\ndef compare(d=32, B=128, n_blocks=6):\n    resnet = ResNet(d, n_blocks)\n    node   = NeuralODE(d, method=\u0027dopri5\u0027)\n    x = torch.randn(B, d)\n    for name, model in [(\u0027ResNet\u0027, resnet), (\u0027NeuralODE\u0027, node)]:\n        t0 = time.perf_counter()\n        for _ in range(10):\n            with torch.no_grad():\n                _ = model(x)\n        ms = (time.perf_counter() - t0) / 10 * 1000\n        n_p = sum(p.numel() for p in model.parameters())\n        print(f\"{name:12s}: {ms:6.1f} ms/forward  {n_p:6d} params\")\n\ncompare()\nprint(\"NeuralODE: adaptive depth (solver NFEs ~ 12-50 for Dopri5 at tol=1e-3)\")\nprint(\"ResNet:    fixed depth (always n_blocks evaluations)\")"},{"type":"callout","variant":"warning","title":"Practical Limitations of Neural ODEs","content":"Neural ODEs are slower than ResNets at equivalent parameter counts due to the overhead of adaptive ODE solvers. Backpropagation through the solver (even with adjoint) requires solving two ODEs. For image generation tasks, discrete normalizing flows (Glow, RealNVP) are faster in practice. Neural ODEs shine for irregular time-series data, latent dynamics modeling, and settings where memory is the primary constraint."},{"type":"heading","level":2,"content":"Advantages and Limitations"},{"type":"text","content":"Neural ODEs offer unique benefits that no discrete-layer architecture can match: continuous-time latent dynamics, memory-efficient gradients via the adjoint, and natural handling of irregular time-series. However, they come with practical costs: ODE solvers add overhead, adaptive step sizes make training time unpredictable, and the smoothness constraint on f limits expressivity. For most image generation tasks, discrete flows or diffusion models are faster. Neural ODEs are most compelling for scientific applications (physics simulations, dynamical systems) and structured latent spaces where continuity is a useful inductive bias."},{"type":"list","ordered":false,"items":["Adaptive compute: solver uses more steps where dynamics are complex, fewer where smooth.","O(1) memory: adjoint method backpropagates without storing intermediate activations.","Continuous time: natural for irregularly-sampled time series (no fixed Δt required).","Continuous normalizing flows: FFJORD achieves flexible densities via Hutchinson trace.","Slow training: each gradient step requires at minimum 2 ODE solves (forward + adjoint).","Limited expressivity in practice: ODE dynamics must be smooth (Lipschitz), limiting expressibility.","Non-intersecting trajectories: flows cannot model multi-modal distributions without augmentation."]},{"type":"heading","level":2,"content":"Model Comparison"},{"type":"table","headers":["Property","ResNet","Neural ODE","FFJORD"],"rows":[["Computation","Discrete, fixed depth","Continuous ODE, adaptive","Continuous ODE, adaptive"],["Memory (backprop)","O(depth)","O(1) via adjoint","O(1) via adjoint"],["Backprop method","Standard autograd","Adjoint ODE solve","Adjoint ODE solve"],["Depth adaptivity","Fixed at build time","Adaptive (solver tolerance)","Adaptive (solver tolerance)"],["Log-det / density","N/A","Exact (O(d^2) per step)","Hutchinson est. (O(d) per step)"],["Main use","Classification, generation","Time-series, latent dynamics","Generative flow, density estimation"]]},{"type":"divider"}]"
---
# Neural ODEs — Continuous-Depth Models

Neural ODEs (Chen et al., 2018) define a model where the hidden state evolves continuously: dx/dt = f(x, t, θ). The output is x(T) = x(0) + ⌠⌡ f(x(t), t, θ) dt, computed by an ODE solver. Instead of a fixed number of discrete layers, the solver adaptively chooses how many function evaluations to use. This gives continuous-time dynamics, O(1) memory backpropagation via the adjoint method, and a natural framework for continuous normalizing flows where the log-determinant evolves via the trace of the Jacobian.

## From Discrete Layers to Continuous Dynamics

A residual network computes x_{l+1} = x_l + f(x_l, θ_l). As the step size Δt → 0 and the number of layers → ∞ with Δt fixed, this converges to the ODE dx/dt = f(x, t, θ). Neural ODE parameterizes f with a neural network and uses an ODE solver (Euler, RK4, or adaptive Dopri5) to integrate from t=0 to t=T. The solver evaluates f multiple times per step; the total number of evaluations is the effective depth, chosen adaptively based on error tolerance.

## ODE Solvers and Adaptive Computation

The Dormand-Prince (Dopri5) solver is a 4(5)th-order Runge-Kutta method with adaptive step size. It estimates the local truncation error by comparing 4th and 5th order solutions; if the error exceeds the tolerance, the step is rejected and retried with a smaller step. This means the solver uses more evaluations in regions where f changes rapidly and fewer where dynamics are smooth. The number of function evaluations is not fixed: it depends on the input, making Neural ODEs irregular compute models.

```python
import torch
import torch.nn as nn
# Install: pip install torchdiffeq
from torchdiffeq import odeint

class ODEFunc(nn.Module):
    """Dynamics: dx/dt = f(x, t, theta). Network takes (x, t_encoded) as input."""
    def __init__(self, d):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(d + 1, 64), nn.Tanh(),
            nn.Linear(64, 64),   nn.Tanh(),
            nn.Linear(64, d))

    def forward(self, t, x):
        t_vec = t.expand(x.shape[0], 1)
        return self.net(torch.cat([x, t_vec], dim=1))

class NeuralODE(nn.Module):
    def __init__(self, d, t_span=(0., 1.), method='dopri5'):
        super().__init__()
        self.func   = ODEFunc(d)
        self.t      = torch.tensor(t_span)
        self.method = method

    def forward(self, x0):
        # odeint returns shape (time_points, batch, d)
        traj = odeint(self.func, x0, self.t, method=self.method)
        return traj[-1]   # final state x(T)

torch.manual_seed(0)
model = NeuralODE(d=4)
x0 = torch.randn(32, 4)
x_T = model(x0)
print(f"Input: {x0.shape} -> Output: {x_T.shape}")
print("Dopri5 adaptively chooses step size; effective depth is input-dependent")
```

## Adjoint Sensitivity Method

Standard autograd stores all intermediate activations from the ODE solver, requiring O(N_steps) memory. The adjoint method avoids this: define the adjoint a(t) = dL/dx(t). It satisfies its own ODE da/dt = -a(t) × (∂f/∂x), solved backward from t=T to t=0. Gradients with respect to θ are obtained by integrating a(t) × (∂f/∂θ) along this trajectory. The backward ODE requires only one ODE solve (no stored activations), giving O(1) memory regardless of solver steps. The trade-off: approximately 2× the compute of the forward pass.

```python
import torch
import torch.nn as nn
# torchdiffeq provides adjoint-based backprop
from torchdiffeq import odeint_adjoint

class AdjointNeuralODE(nn.Module):
    """
    Uses adjoint sensitivity method:
    - Forward: solve ODE from t=0 to T (standard).
    - Backward: solve adjoint ODE from T to 0 — no stored intermediates.
    - Memory: O(1) regardless of number of solver steps.
    """
    def __init__(self, d):
        super().__init__()
        self.func = ODEFunc(d)
        self.t    = torch.tensor([0., 1.])

    def forward(self, x0):
        return odeint_adjoint(
            self.func, x0, self.t,
            method='dopri5',
            adjoint_params=list(self.func.parameters())
        )[-1]

def count_params(m): return sum(p.numel() for p in m.parameters())

torch.manual_seed(42)
d, B = 8, 64
node = AdjointNeuralODE(d)
x0 = torch.randn(B, d, requires_grad=True)
x_T = node(x0)
loss = x_T.sum()
loss.backward()

print(f"Parameters: {count_params(node)}")
print(f"x0 gradient shape: {x0.grad.shape}")
print("Adjoint: backward pass solves another ODE -- O(1) memory, ~2x compute")
print("Standard autograd: O(N_steps) memory -- infeasible for tight tolerances")
```

## Continuous Normalizing Flows (FFJORD)

A Continuous Normalizing Flow (CNF) models the change in log-density as dx evolves: d log p(x) / dt = -Tr(∂f/∂x). Computing the exact trace requires d backward passes (one per output dimension), costing O(d²) per step. FFJORD (Grathwohl et al., 2019) uses Hutchinson's estimator: Tr(J) ≈ E[eᵀ J e] for e ~ N(0,I) or Rademacher. One sample suffices during training, reducing trace cost to O(d) per ODE step. FFJORD achieves competitive log-likelihood with fewer parameters than discrete flows.

```python
import torch
import torch.nn as nn

class CNFDynamics(nn.Module):
    """
    CNF joint dynamics: d(z, log_pz)/dt = (f(z,t), -Tr(df/dz)).
    Hutchinson estimator: Tr(J) ~ e^T (J e) for e ~ Rademacher.
    Reduces O(d^2) exact trace to O(d) per step.
    """
    def __init__(self, d, hidden=64):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(d + 1, hidden), nn.Tanh(),
            nn.Linear(hidden, hidden), nn.Tanh(),
            nn.Linear(hidden, d))

    def forward(self, t, state):
        z, log_pz = state
        t_vec = t.expand(z.shape[0], 1)
        z_in  = torch.cat([z, t_vec], dim=-1).requires_grad_(True)
        f = self.net(z_in)
        # Hutchinson trace estimator
        e = (torch.randint_like(z, 0, 2).float() * 2 - 1)  # Rademacher
        e_Jf = torch.autograd.grad(f, z_in, e, create_graph=True)[0][..., :z.shape[-1]]
        trace_est = (e * e_Jf).sum(dim=-1, keepdim=True)
        return f, -trace_est

def hutchinson_trace_check(d=16, n_est=100):
    """Verify Hutchinson estimator converges to exact trace."""
    J = torch.randn(d, d)
    exact_trace = J.trace().item()
    estimates = [(torch.randn(d) @ J @ torch.randn(d)).item() for _ in range(n_est)]
    print(f"Exact trace: {exact_trace:.4f}")
    print(f"Hutchinson mean ({n_est} samples): {sum(estimates)/n_est:.4f}")
    print("Tr(J) = E[e^T J e] is unbiased for any e with E[ee^T]=I")

hutchinson_trace_check()
```

## Neural ODE vs ResNet

Both ResNets and Neural ODEs compute a sequence of transformations, but ResNets fix the number of function evaluations at graph construction time while Neural ODEs adapt to input complexity. A Neural ODE with tolerance 1e-5 may use 10-100 function evaluations where a 6-block ResNet uses exactly 6. For simple inputs, the ODE solver may need fewer evaluations than the ResNet; for complex inputs, more. This makes Neural ODEs more expressive per parameter but slower and less predictable in wall-clock time.

```python
import torch
import torch.nn as nn
import time

class ResNet(nn.Module):
    def __init__(self, d, n_blocks):
        super().__init__()
        self.blocks = nn.ModuleList([
            nn.Sequential(nn.Linear(d, d), nn.Tanh(), nn.Linear(d, d))
            for _ in range(n_blocks)])
    def forward(self, x):
        for blk in self.blocks:
            x = x + blk(x)
        return x

def compare(d=32, B=128, n_blocks=6):
    resnet = ResNet(d, n_blocks)
    node   = NeuralODE(d, method='dopri5')
    x = torch.randn(B, d)
    for name, model in [('ResNet', resnet), ('NeuralODE', node)]:
        t0 = time.perf_counter()
        for _ in range(10):
            with torch.no_grad():
                _ = model(x)
        ms = (time.perf_counter() - t0) / 10 * 1000
        n_p = sum(p.numel() for p in model.parameters())
        print(f"{name:12s}: {ms:6.1f} ms/forward  {n_p:6d} params")

compare()
print("NeuralODE: adaptive depth (solver NFEs ~ 12-50 for Dopri5 at tol=1e-3)")
print("ResNet:    fixed depth (always n_blocks evaluations)")
```

> **Practical Limitations of Neural ODEs**: Neural ODEs are slower than ResNets at equivalent parameter counts due to the overhead of adaptive ODE solvers. Backpropagation through the solver (even with adjoint) requires solving two ODEs. For image generation tasks, discrete normalizing flows (Glow, RealNVP) are faster in practice. Neural ODEs shine for irregular time-series data, latent dynamics modeling, and settings where memory is the primary constraint.

## Advantages and Limitations

Neural ODEs offer unique benefits that no discrete-layer architecture can match: continuous-time latent dynamics, memory-efficient gradients via the adjoint, and natural handling of irregular time-series. However, they come with practical costs: ODE solvers add overhead, adaptive step sizes make training time unpredictable, and the smoothness constraint on f limits expressivity. For most image generation tasks, discrete flows or diffusion models are faster. Neural ODEs are most compelling for scientific applications (physics simulations, dynamical systems) and structured latent spaces where continuity is a useful inductive bias.

- Adaptive compute: solver uses more steps where dynamics are complex, fewer where smooth.
- O(1) memory: adjoint method backpropagates without storing intermediate activations.
- Continuous time: natural for irregularly-sampled time series (no fixed Δt required).
- Continuous normalizing flows: FFJORD achieves flexible densities via Hutchinson trace.
- Slow training: each gradient step requires at minimum 2 ODE solves (forward + adjoint).
- Limited expressivity in practice: ODE dynamics must be smooth (Lipschitz), limiting expressibility.
- Non-intersecting trajectories: flows cannot model multi-modal distributions without augmentation.

## Model Comparison

| Property | ResNet | Neural ODE | FFJORD |
| --- | --- | --- | --- |
| Computation | Discrete, fixed depth | Continuous ODE, adaptive | Continuous ODE, adaptive |
| Memory (backprop) | O(depth) | O(1) via adjoint | O(1) via adjoint |
| Backprop method | Standard autograd | Adjoint ODE solve | Adjoint ODE solve |
| Depth adaptivity | Fixed at build time | Adaptive (solver tolerance) | Adaptive (solver tolerance) |
| Log-det / density | N/A | Exact (O(d^2) per step) | Hutchinson est. (O(d) per step) |
| Main use | Classification, generation | Time-series, latent dynamics | Generative flow, density estimation |

---

