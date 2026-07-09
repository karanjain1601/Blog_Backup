---
title: "Forward-Mode vs Reverse-Mode Automatic Differentiation"
slug: "automatic-differentiation"
description: "Explains how automatic differentiation works — dual numbers for forward mode, the Wengert tape for reverse mode — and why neural networks always use reverse mode. Includes JAX and gradient checkpointing."
tags: ["calculus", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Automatic differentiation (AD) computes exact derivatives of programs to machine precision — no approximation, no expression swell. It is the engine behind every gradient-based ML framework. Understanding its two modes (forward and reverse) clarifies why neural network training is so computationally efficient, and why certain architectures benefit from gradient checkpointing."},{"type":"heading","level":2,"content":"Why Not Symbolic or Numerical Differentiation?"},{"type":"text","content":"Symbolic differentiation (like a CAS) produces exact expressions but suffers from expression swell — the symbolic gradient of a deep network can be exponentially larger than the original. Numerical differentiation uses finite differences (h small but nonzero), introducing rounding error O(h) or O(h²) and requiring O(n) function evaluations for n parameters. AD avoids both problems."},{"type":"table","headers":["Method","Accuracy","Cost (full gradient)","Extra Memory","Framework"],"rows":[["Symbolic diff","Exact","Expression swell — impractical","Grows with expression","Mathematica, SymPy"],["Numerical (fwd diff)","O(h) error","O(n) evaluations","O(1)","Manual, scipy.optimize"],["Forward-mode AD","Machine precision","O(n) passes for n inputs","O(1) per pass","JAX (jacfwd), Tapenade"],["Reverse-mode AD","Machine precision","O(1) pass for scalar output","O(depth) tape","PyTorch, JAX, TensorFlow"]]},{"type":"heading","level":2,"content":"Forward-Mode AD: Dual Numbers"},{"type":"text","content":"Forward-mode AD augments each real number x with a tangent x\u0027 — forming a dual number x + εx\u0027 where ε² = 0. Arithmetic propagates both the value and its derivative simultaneously. One forward pass with seed x\u0027=1 for input xᵢ gives ∂f/∂xᵢ. For the full gradient you need n forward passes — expensive for many inputs, cheap for many outputs."},{"type":"code","language":"python","content":"import math\n\nclass Dual:\n    # Dual number: val + eps * deriv  (eps^2 = 0)\n    def __init__(self, val, deriv=0.0):\n        self.val   = val\n        self.deriv = deriv\n\n    def __add__(self, other):\n        if isinstance(other, Dual):\n            return Dual(self.val + other.val, self.deriv + other.deriv)\n        return Dual(self.val + other, self.deriv)\n\n    def __radd__(self, other):\n        return self.__add__(other)\n\n    def __mul__(self, other):\n        if isinstance(other, Dual):\n            # product rule: (u*v)\u0027 = u\u0027v + uv\u0027\n            return Dual(self.val * other.val,\n                        self.val * other.deriv + self.deriv * other.val)\n        return Dual(self.val * other, self.deriv * other)\n\n    def __repr__(self):\n        return \u0027Dual(%.6f + eps*%.6f)\u0027 % (self.val, self.deriv)\n\ndef sin_d(x):  return Dual(math.sin(x.val), x.deriv * math.cos(x.val))\ndef exp_d(x):  return Dual(math.exp(x.val), x.deriv * math.exp(x.val))\n\n# f(x) = x^2 * sin(x) + exp(x)  at x=1.5\nx = Dual(1.5, 1.0)    # seed deriv=1 to get df/dx\ny = x * x * sin_d(x) + exp_d(x)\nprint(\u0027f(1.5)               =\u0027, round(y.val,   6))\nprint(\u0027f prime(1.5) [dual]  =\u0027, round(y.deriv, 6))\n\n# Analytical: f\u0027(x) = 2x*sin(x) + x^2*cos(x) + exp(x)\nxv = 1.5\nana = 2*xv*math.sin(xv) + xv**2*math.cos(xv) + math.exp(xv)\nprint(\u0027f prime(1.5) [exact] =\u0027, round(ana, 6))\nprint(\u0027Error:\u0027, abs(y.deriv - ana))"},{"type":"callout","variant":"info","title":"Forward Mode Is Ideal for n \u003c\u003c m","content":"If a function maps 1 input to 1000 outputs (n=1, m=1000), one forward-mode pass gives all 1000 partial derivatives ∂fᵢ/∂x simultaneously. Reverse mode would need 1000 backward passes. JAX\u0027s jacfwd uses vectorized forward mode."},{"type":"heading","level":2,"content":"Reverse-Mode AD: The Tape"},{"type":"text","content":"Reverse-mode AD records operations in the forward pass onto a tape (Wengert list). The backward pass replays the tape in reverse, propagating adjoints (partial derivatives of the output with respect to each intermediate value) from output to inputs. One backward pass computes ∂L/∂xᵢ for ALL i simultaneously — at cost O(1) passes regardless of n."},{"type":"code","language":"python","content":"import torch\n\ndef f(x):\n    # f: R^n -\u003e R  (scalar output, many inputs)\n    return (x**3).sum() + (x[:-1] * x[1:]).sum()\n\n# Reverse-mode: one backward pass gives gradient for ALL n inputs\nn = 12\ntorch.manual_seed(0)\nx = torch.randn(n, requires_grad=True)\ny = f(x)\ny.backward()\n\nprint(\u0027n inputs:\u0027, n)\nprint(\u0027x:      \u0027, x.detach().round(decimals=3).tolist())\nprint(\u0027Gradient:\u0027, x.grad.round(decimals=3).tolist())\n\n# Numerical verification\ndef num_grad(func, x, h=1e-5):\n    g = torch.zeros_like(x)\n    for i in range(len(x)):\n        xp = x.detach().clone(); xm = x.detach().clone()\n        xp[i] += h; xm[i] -= h\n        g[i] = (func(xp) - func(xm)) / (2 * h)\n    return g\n\nng = num_grad(f, x)\nprint(\u0027Numerical:\u0027, ng.round(decimals=3).tolist())\nprint(\u0027Max error:\u0027, (x.grad - ng).abs().max().item())\nprint(\u0027Reverse mode computed gradient for %d inputs in ONE backward pass.\u0027 % n)"},{"type":"heading","level":2,"content":"JAX: Functional AD"},{"type":"text","content":"JAX exposes AD as composable function transformations: jax.grad (reverse-mode gradient), jax.jacrev/jacfwd (Jacobians), jax.jit (XLA compilation), jax.vmap (vectorize over batch). Functions must be pure (no in-place mutation). This compositional design makes it easy to combine grad(jit(vmap(f)))."},{"type":"code","language":"python","content":"# JAX: functional automatic differentiation\n# Install: pip install jax jaxlib\nimport jax\nimport jax.numpy as jnp\n\ndef f_scalar(x):\n    # f: R^n -\u003e R\n    return jnp.sum(x**3) + jnp.sum(x[:-1] * x[1:])\n\ndef f_vector(x):\n    # f: R^n -\u003e R^2\n    return jnp.array([jnp.sum(x**2), jnp.sum(x**3)])\n\nx = jnp.array([1.0, 2.0, 3.0])\n\n# Gradient of scalar function (reverse-mode)\ngrad_f  = jax.grad(f_scalar)\ng = grad_f(x)\nprint(\u0027JAX grad (reverse):\u0027, g.tolist())\n\n# Full Jacobian: jacrev uses reverse-mode (cheap for m outputs)\nJ = jax.jacrev(f_vector)(x)\nprint(\u0027Jacobian (jacrev):\u0027, J.tolist())\n\n# JIT-compile for speed\njit_grad = jax.jit(grad_f)\ng2 = jit_grad(x)\nprint(\u0027JIT gradient:\u0027, g2.tolist())\n\n# vmap: vectorize gradient over batch\nbatch_x = jnp.ones((5, 3))\nbatch_g = jax.vmap(grad_f)(batch_x)\nprint(\u0027Batch gradient shape:\u0027, batch_g.shape)\nprint(\u0027Batch gradients:\u0027)\nprint(batch_g.tolist())"},{"type":"callout","variant":"tip","title":"JAX vs PyTorch AD","content":"Both use reverse-mode AD. JAX requires pure functions (no side effects) but gains composability and XLA compilation. PyTorch\u0027s eager mode is more flexible for debugging. For production training at scale, both are competitive; JAX excels for research requiring custom gradient transformations."},{"type":"heading","level":2,"content":"Gradient Checkpointing"},{"type":"text","content":"Reverse-mode AD must store all intermediate activations from the forward pass on the tape for use in the backward pass. Memory grows with network depth: O(depth) tensors. Gradient checkpointing trades compute for memory by not storing intermediate activations — recomputing them during backward. Reduces memory from O(n) to O(√n) at cost of one extra forward pass."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.utils.checkpoint import checkpoint\n\nclass TransformerBlock(nn.Module):\n    def __init__(self, d):\n        super().__init__()\n        self.fc1 = nn.Linear(d, d * 4)\n        self.act = nn.GELU()\n        self.fc2 = nn.Linear(d * 4, d)\n        self.ln  = nn.LayerNorm(d)\n\n    def forward(self, x):\n        return self.ln(x + self.fc2(self.act(self.fc1(x))))\n\nclass DeepNet(nn.Module):\n    def __init__(self, d, n_layers, use_checkpoint=False):\n        super().__init__()\n        self.blocks = nn.ModuleList([TransformerBlock(d) for _ in range(n_layers)])\n        self.use_ckpt = use_checkpoint\n\n    def forward(self, x):\n        for blk in self.blocks:\n            x = checkpoint(blk, x, use_reentrant=False) if self.use_ckpt else blk(x)\n        return x\n\nd, n_layers = 128, 8\nx = torch.randn(4, d)\n\nfor name, use_ckpt in [(\u0027Normal\u0027, False), (\u0027Checkpointed\u0027, True)]:\n    model = DeepNet(d, n_layers, use_checkpoint=use_ckpt)\n    out   = model(x).sum()\n    out.backward()\n    print(\u0027%s backward: gradients OK\u0027 % name)\n\nprint(\u0027Checkpointing: recomputes activations in backward pass.\u0027)\nprint(\u0027Memory: O(n_layers) -\u003e O(sqrt(n_layers)) with segment checkpointing.\u0027)"},{"type":"heading","level":2,"content":"Why Neural Networks Always Use Reverse Mode"},{"type":"text","content":"A neural network has one output (the scalar loss L) and millions of inputs (the weights). Reverse mode costs O(1) passes to compute ∂L/∂θᵢ for ALL θᵢ simultaneously. Forward mode would cost O(n_params) passes — millions of passes per gradient step. The asymmetry (one output, many inputs) makes reverse mode the only practical choice."},{"type":"list","ordered":false,"items":["Forward mode: cost = O(n_inputs) passes; ideal when n_inputs \u003c\u003c n_outputs","Reverse mode: cost = O(n_outputs) passes; ideal when n_outputs \u003c\u003c n_inputs","Neural network training: 1 scalar loss, millions of weights -\u003e reverse mode wins","JAX jacfwd vs jacrev: choose based on which dimension is smaller","Gradient checkpointing reduces peak activation memory at cost of extra compute","Higher-order gradients (Hessians) require two backward passes or forward-over-reverse"]},{"type":"divider"},{"type":"text","content":"AD is exact (machine precision), composable, and efficient. The key insight is that it does not symbolically differentiate the code — it traces the actual computation and propagates derivatives through the trace, one operation at a time."}]"
---
# Forward-Mode vs Reverse-Mode Automatic Differentiation

Automatic differentiation (AD) computes exact derivatives of programs to machine precision — no approximation, no expression swell. It is the engine behind every gradient-based ML framework. Understanding its two modes (forward and reverse) clarifies why neural network training is so computationally efficient, and why certain architectures benefit from gradient checkpointing.

## Why Not Symbolic or Numerical Differentiation?

Symbolic differentiation (like a CAS) produces exact expressions but suffers from expression swell — the symbolic gradient of a deep network can be exponentially larger than the original. Numerical differentiation uses finite differences (h small but nonzero), introducing rounding error O(h) or O(h²) and requiring O(n) function evaluations for n parameters. AD avoids both problems.

| Method | Accuracy | Cost (full gradient) | Extra Memory | Framework |
| --- | --- | --- | --- | --- |
| Symbolic diff | Exact | Expression swell — impractical | Grows with expression | Mathematica, SymPy |
| Numerical (fwd diff) | O(h) error | O(n) evaluations | O(1) | Manual, scipy.optimize |
| Forward-mode AD | Machine precision | O(n) passes for n inputs | O(1) per pass | JAX (jacfwd), Tapenade |
| Reverse-mode AD | Machine precision | O(1) pass for scalar output | O(depth) tape | PyTorch, JAX, TensorFlow |

## Forward-Mode AD: Dual Numbers

Forward-mode AD augments each real number x with a tangent x' — forming a dual number x + εx' where ε² = 0. Arithmetic propagates both the value and its derivative simultaneously. One forward pass with seed x'=1 for input xᵢ gives ∂f/∂xᵢ. For the full gradient you need n forward passes — expensive for many inputs, cheap for many outputs.

```python
import math

class Dual:
    # Dual number: val + eps * deriv  (eps^2 = 0)
    def __init__(self, val, deriv=0.0):
        self.val   = val
        self.deriv = deriv

    def __add__(self, other):
        if isinstance(other, Dual):
            return Dual(self.val + other.val, self.deriv + other.deriv)
        return Dual(self.val + other, self.deriv)

    def __radd__(self, other):
        return self.__add__(other)

    def __mul__(self, other):
        if isinstance(other, Dual):
            # product rule: (u*v)' = u'v + uv'
            return Dual(self.val * other.val,
                        self.val * other.deriv + self.deriv * other.val)
        return Dual(self.val * other, self.deriv * other)

    def __repr__(self):
        return 'Dual(%.6f + eps*%.6f)' % (self.val, self.deriv)

def sin_d(x):  return Dual(math.sin(x.val), x.deriv * math.cos(x.val))
def exp_d(x):  return Dual(math.exp(x.val), x.deriv * math.exp(x.val))

# f(x) = x^2 * sin(x) + exp(x)  at x=1.5
x = Dual(1.5, 1.0)    # seed deriv=1 to get df/dx
y = x * x * sin_d(x) + exp_d(x)
print('f(1.5)               =', round(y.val,   6))
print('f prime(1.5) [dual]  =', round(y.deriv, 6))

# Analytical: f'(x) = 2x*sin(x) + x^2*cos(x) + exp(x)
xv = 1.5
ana = 2*xv*math.sin(xv) + xv**2*math.cos(xv) + math.exp(xv)
print('f prime(1.5) [exact] =', round(ana, 6))
print('Error:', abs(y.deriv - ana))
```

> **Forward Mode Is Ideal for n << m**: If a function maps 1 input to 1000 outputs (n=1, m=1000), one forward-mode pass gives all 1000 partial derivatives ∂fᵢ/∂x simultaneously. Reverse mode would need 1000 backward passes. JAX's jacfwd uses vectorized forward mode.

## Reverse-Mode AD: The Tape

Reverse-mode AD records operations in the forward pass onto a tape (Wengert list). The backward pass replays the tape in reverse, propagating adjoints (partial derivatives of the output with respect to each intermediate value) from output to inputs. One backward pass computes ∂L/∂xᵢ for ALL i simultaneously — at cost O(1) passes regardless of n.

```python
import torch

def f(x):
    # f: R^n -> R  (scalar output, many inputs)
    return (x**3).sum() + (x[:-1] * x[1:]).sum()

# Reverse-mode: one backward pass gives gradient for ALL n inputs
n = 12
torch.manual_seed(0)
x = torch.randn(n, requires_grad=True)
y = f(x)
y.backward()

print('n inputs:', n)
print('x:      ', x.detach().round(decimals=3).tolist())
print('Gradient:', x.grad.round(decimals=3).tolist())

# Numerical verification
def num_grad(func, x, h=1e-5):
    g = torch.zeros_like(x)
    for i in range(len(x)):
        xp = x.detach().clone(); xm = x.detach().clone()
        xp[i] += h; xm[i] -= h
        g[i] = (func(xp) - func(xm)) / (2 * h)
    return g

ng = num_grad(f, x)
print('Numerical:', ng.round(decimals=3).tolist())
print('Max error:', (x.grad - ng).abs().max().item())
print('Reverse mode computed gradient for %d inputs in ONE backward pass.' % n)
```

## JAX: Functional AD

JAX exposes AD as composable function transformations: jax.grad (reverse-mode gradient), jax.jacrev/jacfwd (Jacobians), jax.jit (XLA compilation), jax.vmap (vectorize over batch). Functions must be pure (no in-place mutation). This compositional design makes it easy to combine grad(jit(vmap(f))).

```python
# JAX: functional automatic differentiation
# Install: pip install jax jaxlib
import jax
import jax.numpy as jnp

def f_scalar(x):
    # f: R^n -> R
    return jnp.sum(x**3) + jnp.sum(x[:-1] * x[1:])

def f_vector(x):
    # f: R^n -> R^2
    return jnp.array([jnp.sum(x**2), jnp.sum(x**3)])

x = jnp.array([1.0, 2.0, 3.0])

# Gradient of scalar function (reverse-mode)
grad_f  = jax.grad(f_scalar)
g = grad_f(x)
print('JAX grad (reverse):', g.tolist())

# Full Jacobian: jacrev uses reverse-mode (cheap for m outputs)
J = jax.jacrev(f_vector)(x)
print('Jacobian (jacrev):', J.tolist())

# JIT-compile for speed
jit_grad = jax.jit(grad_f)
g2 = jit_grad(x)
print('JIT gradient:', g2.tolist())

# vmap: vectorize gradient over batch
batch_x = jnp.ones((5, 3))
batch_g = jax.vmap(grad_f)(batch_x)
print('Batch gradient shape:', batch_g.shape)
print('Batch gradients:')
print(batch_g.tolist())
```

> **JAX vs PyTorch AD**: Both use reverse-mode AD. JAX requires pure functions (no side effects) but gains composability and XLA compilation. PyTorch's eager mode is more flexible for debugging. For production training at scale, both are competitive; JAX excels for research requiring custom gradient transformations.

## Gradient Checkpointing

Reverse-mode AD must store all intermediate activations from the forward pass on the tape for use in the backward pass. Memory grows with network depth: O(depth) tensors. Gradient checkpointing trades compute for memory by not storing intermediate activations — recomputing them during backward. Reduces memory from O(n) to O(√n) at cost of one extra forward pass.

```python
import torch
import torch.nn as nn
from torch.utils.checkpoint import checkpoint

class TransformerBlock(nn.Module):
    def __init__(self, d):
        super().__init__()
        self.fc1 = nn.Linear(d, d * 4)
        self.act = nn.GELU()
        self.fc2 = nn.Linear(d * 4, d)
        self.ln  = nn.LayerNorm(d)

    def forward(self, x):
        return self.ln(x + self.fc2(self.act(self.fc1(x))))

class DeepNet(nn.Module):
    def __init__(self, d, n_layers, use_checkpoint=False):
        super().__init__()
        self.blocks = nn.ModuleList([TransformerBlock(d) for _ in range(n_layers)])
        self.use_ckpt = use_checkpoint

    def forward(self, x):
        for blk in self.blocks:
            x = checkpoint(blk, x, use_reentrant=False) if self.use_ckpt else blk(x)
        return x

d, n_layers = 128, 8
x = torch.randn(4, d)

for name, use_ckpt in [('Normal', False), ('Checkpointed', True)]:
    model = DeepNet(d, n_layers, use_checkpoint=use_ckpt)
    out   = model(x).sum()
    out.backward()
    print('%s backward: gradients OK' % name)

print('Checkpointing: recomputes activations in backward pass.')
print('Memory: O(n_layers) -> O(sqrt(n_layers)) with segment checkpointing.')
```

## Why Neural Networks Always Use Reverse Mode

A neural network has one output (the scalar loss L) and millions of inputs (the weights). Reverse mode costs O(1) passes to compute ∂L/∂θᵢ for ALL θᵢ simultaneously. Forward mode would cost O(n_params) passes — millions of passes per gradient step. The asymmetry (one output, many inputs) makes reverse mode the only practical choice.

- Forward mode: cost = O(n_inputs) passes; ideal when n_inputs << n_outputs
- Reverse mode: cost = O(n_outputs) passes; ideal when n_outputs << n_inputs
- Neural network training: 1 scalar loss, millions of weights -> reverse mode wins
- JAX jacfwd vs jacrev: choose based on which dimension is smaller
- Gradient checkpointing reduces peak activation memory at cost of extra compute
- Higher-order gradients (Hessians) require two backward passes or forward-over-reverse

---

AD is exact (machine precision), composable, and efficient. The key insight is that it does not symbolically differentiate the code — it traces the actual computation and propagates derivatives through the trace, one operation at a time.

