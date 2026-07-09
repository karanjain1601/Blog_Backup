---
title: "JAX — jit, grad, vmap, and pmap"
slug: "jax-functional-transforms"
description: "JAX's four functional transforms — jit (JIT compilation), grad (autodiff), vmap (vectorization), and pmap (multi-device parallelism) — compose to build high-performance ML research code."
tags: ["pytorch", "tools", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"JAX is NumPy-compatible + transformable: any Python function that computes with arrays can be JIT-compiled, differentiated, vectorized, or parallelized by wrapping it in a transformation. The key constraint: functions must be pure (no side effects) so JAX can trace and transform them safely."},{"type":"heading","level":2,"content":"The Four Core Transforms"},{"type":"text","content":"JAX\u0027s power comes from composability: grad(vmap(jit(f))) works, and the result is efficient. Each transform adds one capability without changing the others."},{"type":"list","ordered":false,"items":["jax.jit(f): JIT-compile via XLA — traces f on abstract values, generates fused device kernels, caches compilation","jax.grad(f): compute gradient of f w.r.t. first argument (or argnums) — reverse-mode AD by default","jax.vmap(f): vectorize f over a batch dimension — eliminates explicit loops without modifying f","jax.pmap(f): parallel map over multiple accelerators — each device gets one slice of the input","Pure functions required: no Python globals, no in-place mutation, no I/O inside traced functions","Pytrees: JAX treats nested dicts/lists/tuples of arrays as first-class — model params as dicts work naturally"]},{"type":"heading","level":2,"content":"jit, grad, and vmap Basics"},{"type":"text","content":"These three transforms compose cleanly. vmap(grad(f)) computes per-sample gradients in one vectorized pass — something that would require a Python loop in PyTorch."},{"type":"code","language":"python","content":"import jax\nimport jax.numpy as jnp\nfrom jax import jit, grad, vmap\n\n# Pure function: no side effects, no globals\ndef mse_loss(params, x, y):\n    pred = x @ params[\u0027W\u0027] + params[\u0027b\u0027]\n    return jnp.mean((pred - y) ** 2)\n\n# JIT-compile: first call traces, subsequent calls use compiled kernel\nparams = {\u0027W\u0027: jnp.ones((4, 1)), \u0027b\u0027: jnp.zeros(1)}\nX = jnp.ones((100, 4))\ny = jnp.ones((100, 1))\n\njit_loss = jit(mse_loss)\nprint(f\u0027Loss: {jit_loss(params, X, y):.4f}\u0027)\n\n# grad: derivative w.r.t. params (argnums=0 is the default)\ngrad_fn = jit(grad(mse_loss, argnums=0))\ngrads = grad_fn(params, X, y)\nprint(f\u0027Gradient keys:    {list(grads.keys())}\u0027)\nprint(f\u0027Gradient W shape: {grads[\"W\"].shape}\u0027)\n\n# vmap: vectorize a per-sample function over a batch axis\ndef single_sample_loss(params, x_single, y_single):\n    pred = x_single @ params[\u0027W\u0027] + params[\u0027b\u0027]\n    return jnp.mean((pred - y_single) ** 2)\n\nbatch_grad_fn = vmap(grad(single_sample_loss), in_axes=(None, 0, 0))\nper_sample_grads = batch_grad_fn(params, X, y)  # per-sample gradients!\nprint(f\u0027Per-sample grad W shape: {per_sample_grads[\"W\"].shape}\u0027)  # (100, 4, 1)"},{"type":"heading","level":2,"content":"Full JAX Training Loop"},{"type":"text","content":"A functional JAX training loop explicitly passes state (params, optimizer state) as arguments and returns updated state. No classes or mutations — every step is a pure function that can be jit-compiled."},{"type":"code","language":"python","content":"import jax\nimport jax.numpy as jnp\nfrom jax import jit, grad, random\nimport optax  # JAX optimizer library\n\n# Initialize params as a pytree dict\nkey = random.PRNGKey(42)\nparams = {\n    \u0027W1\u0027: random.normal(key, (20, 64)) * 0.1,\n    \u0027b1\u0027: jnp.zeros(64),\n    \u0027W2\u0027: random.normal(key, (64, 2)) * 0.1,\n    \u0027b2\u0027: jnp.zeros(2)\n}\n\ndef forward(params, x):\n    h = jnp.tanh(x @ params[\u0027W1\u0027] + params[\u0027b1\u0027])\n    return h @ params[\u0027W2\u0027] + params[\u0027b2\u0027]\n\ndef cross_entropy_loss(params, x, y):\n    logits = forward(params, x)\n    log_probs = jax.nn.log_softmax(logits, axis=-1)\n    return -jnp.mean(log_probs[jnp.arange(len(y)), y])\n\n# Optax optimizer: Adam\noptimizer = optax.adam(learning_rate=1e-3)\nopt_state  = optimizer.init(params)\n\n@jit\ndef train_step(params, opt_state, x, y):\n    loss, grads = jax.value_and_grad(cross_entropy_loss)(params, x, y)\n    updates, new_opt_state = optimizer.update(grads, opt_state)\n    new_params = optax.apply_updates(params, updates)\n    return new_params, new_opt_state, loss\n\n# Training loop\nkey, subkey = random.split(key)\nX_data = random.normal(subkey, (500, 20))\ny_data = random.randint(key, (500,), 0, 2)\nfor step in range(5):\n    params, opt_state, loss = train_step(params, opt_state, X_data, y_data)\n    print(f\u0027Step {step+1}: loss={loss:.4f}\u0027)"},{"type":"heading","level":2,"content":"vmap for Per-Sample Gradient Computation"},{"type":"text","content":"Per-sample gradients are required for differential privacy (DP-SGD) and influence function computation. In PyTorch this requires a Python loop over the batch; in JAX, vmap(grad(f)) computes them efficiently in one vectorized pass."},{"type":"code","language":"python","content":"import jax\nimport jax.numpy as jnp\nfrom jax import vmap, grad, jit, random\n\nkey = random.PRNGKey(0)\nparams = {\u0027W\u0027: random.normal(key, (10, 5)), \u0027b\u0027: jnp.zeros(5)}\n\ndef single_loss(params, x_i, y_i):\n    logit = x_i @ params[\u0027W\u0027] + params[\u0027b\u0027]\n    return jax.nn.softmax_cross_entropy_with_integer_labels(logit, y_i)\n\n# vmap over batch dimension: in_axes=(None, 0, 0)\n# params: same for all samples (None), x and y: one per sample (0)\nbatch_grads_fn = jit(vmap(grad(single_loss), in_axes=(None, 0, 0)))\n\nX_batch = random.normal(key, (64, 10))   # 64 samples, 10 features\ny_batch = random.randint(key, (64,), 0, 5)  # 64 labels\n\nper_sample_grads = batch_grads_fn(params, X_batch, y_batch)\nprint(f\u0027Per-sample grad W: {per_sample_grads[\"W\"].shape}\u0027)  # (64, 10, 5)\n\n# For DP-SGD: clip each per-sample gradient, then aggregate\nmax_norm = 1.0\nclipped_W = jnp.clip(\n    per_sample_grads[\u0027W\u0027],\n    -max_norm / jnp.sqrt(10 * 5),\n    max_norm / jnp.sqrt(10 * 5)\n)\nmean_grad_W = clipped_W.mean(axis=0)\nprint(f\u0027Clipped mean grad W: {mean_grad_W.shape}\u0027)  # (10, 5)"},{"type":"heading","level":2,"content":"pmap for Multi-Device Data Parallelism"},{"type":"text","content":"pmap maps a function over the first axis of each array, distributing slices across all available devices. Each device runs the same computation on its data slice, with collective operations (like lax.pmean) to synchronize."},{"type":"code","language":"python","content":"import jax\nimport jax.numpy as jnp\nfrom jax import pmap, random\nfrom jax.lax import pmean\n\nn_devices = jax.device_count()\nprint(f\u0027Available devices: {n_devices}\u0027)\n\n# Replicate params across all devices\ndef replicate(x):\n    return jnp.broadcast_to(x, (n_devices,) + x.shape)\n\nkey = random.PRNGKey(42)\nparams_rep = {\n    \u0027W\u0027: replicate(random.normal(key, (10, 5))),\n    \u0027b\u0027: replicate(jnp.zeros(5))\n}\n\n@pmap\ndef parallel_train_step(params, x_shard, y_shard):\n    def loss_fn(p):\n        logit = x_shard @ p[\u0027W\u0027] + p[\u0027b\u0027]\n        return jnp.mean((logit - y_shard) ** 2)\n    grads = jax.grad(loss_fn)(params)\n    # Average gradients across devices (allreduce)\n    grads = jax.tree_util.tree_map(lambda g: pmean(g, axis_name=\u0027batch\u0027), grads)\n    return grads\n\nprint(f\u0027pmap distributes batch axis over {n_devices} device(s)\u0027)"},{"type":"divider"},{"type":"heading","level":2,"content":"JAX vs PyTorch Comparison"},{"type":"table","headers":["Aspect","PyTorch","JAX"],"rows":[["Programming model","Object-oriented (nn.Module, state in object)","Functional — state passed explicitly as pytrees"],["Autodiff","Dynamic graph, eager backward()","Composable transforms: grad, value_and_grad"],["Vectorization","Manual loop or torch.vmap (newer)","vmap — first-class, composes with grad"],["Parallelism","DistributedDataParallel, FSDP","pmap — elegant but limited to one host"],["Debugging","Eager mode, pdb-friendly","Harder — traced functions can\u0027t print inside jit"],["Ecosystem","Massive (HuggingFace, timm, etc.)","Growing (Flax, Haiku, Optax, Equinox)"]]},{"type":"callout","variant":"info","title":"JAX\u0027s Pure Function Requirement","content":"JAX traces functions by running them with abstract values, not real data. Any Python side effect inside a jit-compiled function (print, global mutation, randomness without explicit key splitting) produces incorrect behavior — the side effect only happens during tracing, not at runtime. Always pass jax.random.PRNGKey explicitly and split keys for each operation that needs randomness."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["jit compiles via XLA — first call traces, subsequent calls run compiled kernel; no model changes needed","grad differentiates any pure Python function — composes with jit and vmap freely","vmap vectorizes a per-element function over a batch dimension — replaces Python loops","pmap parallelizes over multiple accelerators with collective operations for gradient averaging","Pure functions required: no side effects, explicit state passing, explicit PRNG key splitting"]}]"
---
# JAX — jit, grad, vmap, and pmap

JAX is NumPy-compatible + transformable: any Python function that computes with arrays can be JIT-compiled, differentiated, vectorized, or parallelized by wrapping it in a transformation. The key constraint: functions must be pure (no side effects) so JAX can trace and transform them safely.

## The Four Core Transforms

JAX's power comes from composability: grad(vmap(jit(f))) works, and the result is efficient. Each transform adds one capability without changing the others.

- jax.jit(f): JIT-compile via XLA — traces f on abstract values, generates fused device kernels, caches compilation
- jax.grad(f): compute gradient of f w.r.t. first argument (or argnums) — reverse-mode AD by default
- jax.vmap(f): vectorize f over a batch dimension — eliminates explicit loops without modifying f
- jax.pmap(f): parallel map over multiple accelerators — each device gets one slice of the input
- Pure functions required: no Python globals, no in-place mutation, no I/O inside traced functions
- Pytrees: JAX treats nested dicts/lists/tuples of arrays as first-class — model params as dicts work naturally

## jit, grad, and vmap Basics

These three transforms compose cleanly. vmap(grad(f)) computes per-sample gradients in one vectorized pass — something that would require a Python loop in PyTorch.

```python
import jax
import jax.numpy as jnp
from jax import jit, grad, vmap

# Pure function: no side effects, no globals
def mse_loss(params, x, y):
    pred = x @ params['W'] + params['b']
    return jnp.mean((pred - y) ** 2)

# JIT-compile: first call traces, subsequent calls use compiled kernel
params = {'W': jnp.ones((4, 1)), 'b': jnp.zeros(1)}
X = jnp.ones((100, 4))
y = jnp.ones((100, 1))

jit_loss = jit(mse_loss)
print(f'Loss: {jit_loss(params, X, y):.4f}')

# grad: derivative w.r.t. params (argnums=0 is the default)
grad_fn = jit(grad(mse_loss, argnums=0))
grads = grad_fn(params, X, y)
print(f'Gradient keys:    {list(grads.keys())}')
print(f'Gradient W shape: {grads["W"].shape}')

# vmap: vectorize a per-sample function over a batch axis
def single_sample_loss(params, x_single, y_single):
    pred = x_single @ params['W'] + params['b']
    return jnp.mean((pred - y_single) ** 2)

batch_grad_fn = vmap(grad(single_sample_loss), in_axes=(None, 0, 0))
per_sample_grads = batch_grad_fn(params, X, y)  # per-sample gradients!
print(f'Per-sample grad W shape: {per_sample_grads["W"].shape}')  # (100, 4, 1)
```

## Full JAX Training Loop

A functional JAX training loop explicitly passes state (params, optimizer state) as arguments and returns updated state. No classes or mutations — every step is a pure function that can be jit-compiled.

```python
import jax
import jax.numpy as jnp
from jax import jit, grad, random
import optax  # JAX optimizer library

# Initialize params as a pytree dict
key = random.PRNGKey(42)
params = {
    'W1': random.normal(key, (20, 64)) * 0.1,
    'b1': jnp.zeros(64),
    'W2': random.normal(key, (64, 2)) * 0.1,
    'b2': jnp.zeros(2)
}

def forward(params, x):
    h = jnp.tanh(x @ params['W1'] + params['b1'])
    return h @ params['W2'] + params['b2']

def cross_entropy_loss(params, x, y):
    logits = forward(params, x)
    log_probs = jax.nn.log_softmax(logits, axis=-1)
    return -jnp.mean(log_probs[jnp.arange(len(y)), y])

# Optax optimizer: Adam
optimizer = optax.adam(learning_rate=1e-3)
opt_state  = optimizer.init(params)

@jit
def train_step(params, opt_state, x, y):
    loss, grads = jax.value_and_grad(cross_entropy_loss)(params, x, y)
    updates, new_opt_state = optimizer.update(grads, opt_state)
    new_params = optax.apply_updates(params, updates)
    return new_params, new_opt_state, loss

# Training loop
key, subkey = random.split(key)
X_data = random.normal(subkey, (500, 20))
y_data = random.randint(key, (500,), 0, 2)
for step in range(5):
    params, opt_state, loss = train_step(params, opt_state, X_data, y_data)
    print(f'Step {step+1}: loss={loss:.4f}')
```

## vmap for Per-Sample Gradient Computation

Per-sample gradients are required for differential privacy (DP-SGD) and influence function computation. In PyTorch this requires a Python loop over the batch; in JAX, vmap(grad(f)) computes them efficiently in one vectorized pass.

```python
import jax
import jax.numpy as jnp
from jax import vmap, grad, jit, random

key = random.PRNGKey(0)
params = {'W': random.normal(key, (10, 5)), 'b': jnp.zeros(5)}

def single_loss(params, x_i, y_i):
    logit = x_i @ params['W'] + params['b']
    return jax.nn.softmax_cross_entropy_with_integer_labels(logit, y_i)

# vmap over batch dimension: in_axes=(None, 0, 0)
# params: same for all samples (None), x and y: one per sample (0)
batch_grads_fn = jit(vmap(grad(single_loss), in_axes=(None, 0, 0)))

X_batch = random.normal(key, (64, 10))   # 64 samples, 10 features
y_batch = random.randint(key, (64,), 0, 5)  # 64 labels

per_sample_grads = batch_grads_fn(params, X_batch, y_batch)
print(f'Per-sample grad W: {per_sample_grads["W"].shape}')  # (64, 10, 5)

# For DP-SGD: clip each per-sample gradient, then aggregate
max_norm = 1.0
clipped_W = jnp.clip(
    per_sample_grads['W'],
    -max_norm / jnp.sqrt(10 * 5),
    max_norm / jnp.sqrt(10 * 5)
)
mean_grad_W = clipped_W.mean(axis=0)
print(f'Clipped mean grad W: {mean_grad_W.shape}')  # (10, 5)
```

## pmap for Multi-Device Data Parallelism

pmap maps a function over the first axis of each array, distributing slices across all available devices. Each device runs the same computation on its data slice, with collective operations (like lax.pmean) to synchronize.

```python
import jax
import jax.numpy as jnp
from jax import pmap, random
from jax.lax import pmean

n_devices = jax.device_count()
print(f'Available devices: {n_devices}')

# Replicate params across all devices
def replicate(x):
    return jnp.broadcast_to(x, (n_devices,) + x.shape)

key = random.PRNGKey(42)
params_rep = {
    'W': replicate(random.normal(key, (10, 5))),
    'b': replicate(jnp.zeros(5))
}

@pmap
def parallel_train_step(params, x_shard, y_shard):
    def loss_fn(p):
        logit = x_shard @ p['W'] + p['b']
        return jnp.mean((logit - y_shard) ** 2)
    grads = jax.grad(loss_fn)(params)
    # Average gradients across devices (allreduce)
    grads = jax.tree_util.tree_map(lambda g: pmean(g, axis_name='batch'), grads)
    return grads

print(f'pmap distributes batch axis over {n_devices} device(s)')
```

---

## JAX vs PyTorch Comparison

| Aspect | PyTorch | JAX |
| --- | --- | --- |
| Programming model | Object-oriented (nn.Module, state in object) | Functional — state passed explicitly as pytrees |
| Autodiff | Dynamic graph, eager backward() | Composable transforms: grad, value_and_grad |
| Vectorization | Manual loop or torch.vmap (newer) | vmap — first-class, composes with grad |
| Parallelism | DistributedDataParallel, FSDP | pmap — elegant but limited to one host |
| Debugging | Eager mode, pdb-friendly | Harder — traced functions can't print inside jit |
| Ecosystem | Massive (HuggingFace, timm, etc.) | Growing (Flax, Haiku, Optax, Equinox) |

> **JAX's Pure Function Requirement**: JAX traces functions by running them with abstract values, not real data. Any Python side effect inside a jit-compiled function (print, global mutation, randomness without explicit key splitting) produces incorrect behavior — the side effect only happens during tracing, not at runtime. Always pass jax.random.PRNGKey explicitly and split keys for each operation that needs randomness.

## Key Takeaways

- jit compiles via XLA — first call traces, subsequent calls run compiled kernel; no model changes needed
- grad differentiates any pure Python function — composes with jit and vmap freely
- vmap vectorizes a per-element function over a batch dimension — replaces Python loops
- pmap parallelizes over multiple accelerators with collective operations for gradient averaging
- Pure functions required: no side effects, explicit state passing, explicit PRNG key splitting

