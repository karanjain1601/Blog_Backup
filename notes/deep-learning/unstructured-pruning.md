---
title: "Unstructured Pruning — Weight Magnitude and Gradual Pruning"
slug: "unstructured-pruning"
description: "Unstructured pruning zeros individual weights by magnitude, producing sparse models. Covers global vs local pruning, the Zhu & Gupta polynomial gradual schedule, prune-retrain cycles, the PyTorch prune API, GPU acceleration limitations, and the lottery ticket hypothesis connection."
tags: ["deep-learning", "model-compression", "knowledge-distillation", "pruning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Unstructured pruning removes individual weights from a neural network based on their magnitude: weights with small absolute values contribute little to the network\u0027s output and can be zeroed without large accuracy loss. Unlike structured pruning, which removes entire filters or layers, unstructured pruning is architecture-agnostic and can achieve very high sparsity (90-99%) with surprisingly small accuracy drops when combined with a gradual schedule and fine-tuning. The trade-off is that the resulting sparse weight matrices do not accelerate inference on standard GPU hardware without specialised support."},{"type":"heading","level":2,"content":"Global vs Local Magnitude Pruning"},{"type":"text","content":"Global pruning ranks all weights across the entire network by |w_i| and prunes the bottom p% regardless of layer. This allows sparsity to concentrate in redundant layers — fully connected layers typically accumulate much higher sparsity than convolutional layers under global pruning. Local pruning applies the same ratio p% independently within each layer. Local pruning avoids layer collapse (a single layer losing too many weights) but is less accurate than global pruning at high sparsity because it cannot reallocate the sparsity budget from redundant to important layers."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.utils.prune as prune\n\ndef apply_global_magnitude_pruning(model: nn.Module, sparsity: float):\n    \"\"\"Prune globally: rank all weights together, zero the bottom sparsity%.\"\"\"\n    params = [(m, \u0027weight\u0027) for m in model.modules()\n               if isinstance(m, (nn.Linear, nn.Conv2d))]\n    prune.global_unstructured(params, pruning_method=prune.L1Unstructured, amount=sparsity)\n    total = sum(m.weight.numel() for m, _ in params)\n    zero  = sum((m.weight == 0).sum().item() for m, _ in params)\n    print(f\u0027Global pruning: target={sparsity:.0%}  actual={zero/total:.1%}  ({zero}/{total} zeros)\u0027)\n\ndef apply_local_magnitude_pruning(model: nn.Module, sparsity: float):\n    \"\"\"Prune locally: zero bottom sparsity% within each layer independently.\"\"\"\n    for module in model.modules():\n        if isinstance(module, (nn.Linear, nn.Conv2d)):\n            prune.l1_unstructured(module, name=\u0027weight\u0027, amount=sparsity)\n    mods  = [m for m in model.modules() if isinstance(m, (nn.Linear, nn.Conv2d))]\n    total = sum(m.weight.numel() for m in mods)\n    zero  = sum((m.weight == 0).sum().item() for m in mods)\n    print(f\u0027Local pruning:  target={sparsity:.0%}  actual={zero/total:.1%}  ({zero}/{total} zeros)\u0027)\n\ndef remove_masks(model: nn.Module):\n    \"\"\"Make pruning permanent by removing reparameterisation masks.\"\"\"\n    for m in model.modules():\n        if isinstance(m, (nn.Linear, nn.Conv2d)):\n            try: prune.remove(m, \u0027weight\u0027)\n            except ValueError: pass\n\nmodel = nn.Sequential(nn.Linear(784, 256), nn.ReLU(), nn.Linear(256, 10))\napply_global_magnitude_pruning(model, 0.7)\nremove_masks(model)\nprint(\u0027prune.remove() converts weight_orig + weight_mask -\u003e weight (permanent).\u0027)"},{"type":"heading","level":2,"content":"Weight Distribution After Pruning"},{"type":"text","content":"Before pruning, neural network weights follow an approximately Gaussian distribution centred near zero. After magnitude pruning, the distribution becomes bimodal: a sharp spike at exactly zero (the pruned weights) and a broader distribution of large-magnitude survivors. The bimodal signature can be detected by plotting weight histograms. The PyTorch prune API implements pruning via reparameterisation: it stores weight_orig (original values) and a binary weight_mask, computing weight = weight_orig * weight_mask on each forward pass. Calling prune.remove() collapses this into a single sparse weight tensor."},{"type":"heading","level":2,"content":"Gradual Pruning Schedule (Zhu \u0026 Gupta 2018)"},{"type":"text","content":"One-shot pruning — removing all target weights at once — causes a large accuracy drop that fine-tuning may not recover. Zhu \u0026 Gupta (2018) proposed gradual pruning with a polynomial schedule: s(t) = s_f + (s_i - s_f)(1 - (t-t₀)/(n·Δt))³, where t₀ is the start step, n is the number of pruning steps, and Δt is the step interval. The cubic polynomial gives a slow start (minimal early pruning), aggressive middle phase, and slow finish (fine-grained tuning at high sparsity). Pruning is applied every Δt training steps, with normal gradient updates continuing between steps so the network can redistribute information after each pruning event."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.utils.prune as prune\n\ndef polynomial_sparsity(step: int, t0: int, n_steps: int, delta_t: int,\n                         s_i: float = 0.0, s_f: float = 0.9) -\u003e float:\n    \"\"\"\n    Zhu \u0026 Gupta (2018) cubic polynomial pruning schedule.\n    s(t) = s_f + (s_i - s_f) * (1 - (t - t0) / (n * delta_t))^3\n    \"\"\"\n    if step \u003c t0:\n        return 0.0\n    if step \u003e= t0 + n_steps * delta_t:\n        return s_f\n    progress = (step - t0) / (n_steps * delta_t)\n    return s_f + (s_i - s_f) * (1.0 - progress) ** 3\n\ndef gradual_prune_step(model: nn.Module, step: int, t0: int,\n                        n_steps: int, delta_t: int, s_f: float = 0.9):\n    \"\"\"Apply pruning to reach the scheduled sparsity at this training step.\"\"\"\n    if step % delta_t != 0:\n        return 0.0  # only prune at scheduled intervals\n    current_s = polynomial_sparsity(step, t0, n_steps, delta_t, s_f=s_f)\n    if current_s \u003e 0:\n        params = [(m, \u0027weight\u0027) for m in model.modules()\n                   if isinstance(m, (nn.Linear, nn.Conv2d))]\n        prune.global_unstructured(params, prune.L1Unstructured, amount=current_s)\n    return current_s\n\n# Visualise schedule: t0=100, n=10, delta_t=100, s_f=0.9\nprint(f\u0027{\"Step\":\u003e6}  {\"Scheduled Sparsity\":\u003e20}\u0027)\nfor step in [0, 100, 200, 400, 700, 1000, 1100, 1200]:\n    s = polynomial_sparsity(step, t0=100, n_steps=10, delta_t=100, s_f=0.9)\n    print(f\u0027{step:\u003e6}  {s:\u003e20.1%}\u0027)"},{"type":"heading","level":2,"content":"Prune-Retrain Cycles and Weight Recovery"},{"type":"text","content":"Between each scheduled pruning step, the network is trained normally via backpropagation. Pruned weights receive zero gradient (they are masked), but surviving weights can grow in magnitude to compensate. This redistribution is the key mechanism behind gradual pruning\u0027s accuracy advantage: surviving weights specialise to cover the functions of the removed ones. The learning rate during gradual pruning should be 10-30% of the original training LR — too high causes instability when the mask suddenly changes, too low prevents recovery. After reaching target sparsity, a final fine-tuning phase at 1% of original LR polishes the sparse model."},{"type":"heading","level":2,"content":"GPU Acceleration Limitations"},{"type":"text","content":"A common misconception is that a 90% sparse model runs 10x faster. This is false for standard GPU hardware. GPU matrix multiplication is implemented as dense GEMM via cuBLAS. A weight matrix with 90% zeros still performs the full M×K×N multiply-add operations — the hardware does not skip zero multiplications. Zero weights are multiplied by activations, producing zero products that accumulate normally: wasted compute, not skipped compute. Real speedup from unstructured sparsity requires: (1) NVIDIA A100+ with N:M sparsity (50% sparsity, 2x speedup), (2) custom SpMM kernels on CPU, or (3) structured pruning that reduces matrix dimensions."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.utils.prune as prune\nimport time\n\ndef timed_inference(model: nn.Module, x: torch.Tensor,\n                     n_warmup: int = 5, n_runs: int = 30) -\u003e float:\n    \"\"\"Return average inference time (ms) over n_runs forward passes.\"\"\"\n    model.eval()\n    if x.is_cuda: torch.cuda.synchronize()\n    for _ in range(n_warmup):\n        with torch.no_grad(): _ = model(x)\n    if x.is_cuda: torch.cuda.synchronize()\n    t0 = time.perf_counter()\n    for _ in range(n_runs):\n        with torch.no_grad(): _ = model(x)\n    if x.is_cuda: torch.cuda.synchronize()\n    return (time.perf_counter() - t0) / n_runs * 1000\n\ndevice = torch.device(\u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027)\nmodel  = nn.Sequential(nn.Linear(1024, 2048), nn.ReLU(), nn.Linear(2048, 10)).to(device)\nx      = torch.randn(64, 1024, device=device)\n\ndense_ms = timed_inference(model, x)\n\nparams = [(m, \u0027weight\u0027) for m in model.modules() if isinstance(m, nn.Linear)]\nprune.global_unstructured(params, prune.L1Unstructured, amount=0.9)\nsparse_ms = timed_inference(model, x)\n\nprint(f\u0027Device: {device}\u0027)\nprint(f\u0027Dense model (0% sparsity):    {dense_ms:.3f} ms/batch\u0027)\nprint(f\u0027Sparse model (90% sparsity):  {sparse_ms:.3f} ms/batch\u0027)\nprint(f\u0027Speedup: {dense_ms/sparse_ms:.2f}x  (expected ~1.0x without hardware support)\u0027)\nprint(\u0027Unstructured sparsity: zeros still participate in dense matmul on standard GPU.\u0027)\nprint(\u0027Need N:M sparsity (A100 Sparse Tensor Cores) or structured pruning for speedup.\u0027)"},{"type":"heading","level":2,"content":"Accuracy vs Sparsity Curve"},{"type":"text","content":"Empirical studies show that with gradual magnitude pruning, ResNet-20 on CIFAR-10 maintains accuracy within 1% of the baseline up to ~80% sparsity. Beyond 90%, accuracy drops steeply — the accuracy cliff. The cliff location depends on model size: larger models (ResNet-50 on ImageNet) maintain accuracy up to 95% sparsity due to higher over-parameterisation. Local pruning shifts the cliff to lower sparsity than global pruning because it cannot reallocate the budget from redundant to critical layers. Gradual pruning extends the cliff by ~5% absolute sparsity compared to one-shot pruning."},{"type":"code","language":"python","content":"import numpy as np\n\n# ResNet-20 on CIFAR-10: accuracy under different pruning strategies\nsparsity  = [0.0,  0.5,  0.7,  0.9,  0.95, 0.99]\nmag_glob  = [91.8, 91.3, 90.7, 87.9, 82.1, 60.3]  # global magnitude, one-shot\nmag_local = [91.8, 90.8, 89.5, 84.8, 76.5, 51.2]  # local magnitude, one-shot\ngradual   = [91.8, 91.6, 91.2, 89.7, 85.4, 66.8]  # gradual schedule (Zhu \u0026 Gupta)\n\nprint(f\u0027{\"Sparsity\":\u003e10}  {\"Global Mag\":\u003e12}  {\"Local Mag\":\u003e11}  {\"Gradual\":\u003e9}  {\"Gradual Gain\":\u003e14}\u0027)\nprint(\u0027-\u0027 * 64)\nfor s, g, l, gr in zip(sparsity, mag_glob, mag_local, gradual):\n    gain = gr - g\n    print(f\u0027{s:\u003e10.0%}  {g:\u003e12.1f}  {l:\u003e11.1f}  {gr:\u003e9.1f}  {gain:\u003e+14.1f}\u0027)\n\nbaseline = mag_glob[0]\ncliff_global  = next((s for s, a in zip(sparsity, mag_glob)  if baseline - a \u003e 2), None)\ncliff_gradual = next((s for s, a in zip(sparsity, gradual)   if baseline - a \u003e 2), None)\nprint(f\u0027\\nAccuracy cliff (\u003e2pp drop): global={cliff_global:.0%}  gradual={cliff_gradual:.0%}\u0027)\nmean_benefit = np.mean([gr - g for gr, g in zip(gradual[1:], mag_glob[1:])])\nprint(f\u0027Mean accuracy benefit of gradual over one-shot: +{mean_benefit:.1f} pp\u0027)"},{"type":"heading","level":2,"content":"Lottery Ticket Hypothesis Connection"},{"type":"text","content":"Frankle \u0026 Carlin (2019) observed that within a large dense network there exist sparse subnetworks — winning tickets — that, when trained from the original weight initialisation, match the full network\u0027s accuracy. These are identified by training the full network, pruning the smallest weights, and resetting surviving weights to their initial values. Critically, the lottery ticket must be trained from the same initialisation — randomly reinitialising the surviving weights fails. Iterative magnitude pruning (IMP) is the practical algorithm: prune 20% of remaining weights per cycle, reset to original init, retrain."},{"type":"callout","variant":"info","title":"When Unstructured Pruning Is the Right Choice","content":"Choose unstructured pruning when: (1) targeting a CPU with a sparse linear algebra library (MKL sparse BLAS, oneDNN), (2) you have an A100+ GPU and can use 2:4 N:M sparsity for 2x throughput, (3) experimenting with lottery tickets and need extreme sparsity (\u003e90%) with minimal accuracy loss, or (4) model storage and memory footprint are the bottleneck rather than inference latency. For raw GPU inference speedup on standard hardware, structured pruning or INT8 quantisation are more effective choices."},{"type":"table","headers":["Sparsity","Accuracy (ResNet-20 CIFAR-10)","Non-Zero Params","Model Size","GPU Speedup","CPU Speedup (SpMM)"],"rows":[["0% (dense)","91.8%","100%","1.0x","1.0x","1.0x"],["50%","91.3%","50%","~0.6x","~1.0x (no benefit)","~1.2x"],["70%","90.7%","30%","~0.4x","~1.0x","~1.8x"],["90%","87.9%","10%","~0.2x","~1.0x","~3.5x"],["90% N:M (A100)","91.2%","50% (structured)","~0.6x","~2.0x","N/A"]]},{"type":"list","ordered":false,"items":["Global pruning concentrates sparsity in over-parameterised layers; local pruning applies a uniform ratio per layer.","PyTorch prune API: prune.l1_unstructured for local, prune.global_unstructured for global magnitude pruning.","prune.remove() collapses weight_orig + weight_mask into a single sparse weight tensor permanently.","Zhu \u0026 Gupta cubic schedule: slow start, aggressive middle, slow finish — better than linear or step schedules.","Accuracy cliff: above ~80-90% sparsity for most architectures, accuracy drops sharply with magnitude pruning.","Lottery ticket: winning ticket subnetworks require the exact original initialisation — random reset fails."]},{"type":"divider"}]"
---
# Unstructured Pruning — Weight Magnitude and Gradual Pruning

Unstructured pruning removes individual weights from a neural network based on their magnitude: weights with small absolute values contribute little to the network's output and can be zeroed without large accuracy loss. Unlike structured pruning, which removes entire filters or layers, unstructured pruning is architecture-agnostic and can achieve very high sparsity (90-99%) with surprisingly small accuracy drops when combined with a gradual schedule and fine-tuning. The trade-off is that the resulting sparse weight matrices do not accelerate inference on standard GPU hardware without specialised support.

## Global vs Local Magnitude Pruning

Global pruning ranks all weights across the entire network by |w_i| and prunes the bottom p% regardless of layer. This allows sparsity to concentrate in redundant layers — fully connected layers typically accumulate much higher sparsity than convolutional layers under global pruning. Local pruning applies the same ratio p% independently within each layer. Local pruning avoids layer collapse (a single layer losing too many weights) but is less accurate than global pruning at high sparsity because it cannot reallocate the sparsity budget from redundant to important layers.

```python
import torch
import torch.nn as nn
import torch.nn.utils.prune as prune

def apply_global_magnitude_pruning(model: nn.Module, sparsity: float):
    """Prune globally: rank all weights together, zero the bottom sparsity%."""
    params = [(m, 'weight') for m in model.modules()
               if isinstance(m, (nn.Linear, nn.Conv2d))]
    prune.global_unstructured(params, pruning_method=prune.L1Unstructured, amount=sparsity)
    total = sum(m.weight.numel() for m, _ in params)
    zero  = sum((m.weight == 0).sum().item() for m, _ in params)
    print(f'Global pruning: target={sparsity:.0%}  actual={zero/total:.1%}  ({zero}/{total} zeros)')

def apply_local_magnitude_pruning(model: nn.Module, sparsity: float):
    """Prune locally: zero bottom sparsity% within each layer independently."""
    for module in model.modules():
        if isinstance(module, (nn.Linear, nn.Conv2d)):
            prune.l1_unstructured(module, name='weight', amount=sparsity)
    mods  = [m for m in model.modules() if isinstance(m, (nn.Linear, nn.Conv2d))]
    total = sum(m.weight.numel() for m in mods)
    zero  = sum((m.weight == 0).sum().item() for m in mods)
    print(f'Local pruning:  target={sparsity:.0%}  actual={zero/total:.1%}  ({zero}/{total} zeros)')

def remove_masks(model: nn.Module):
    """Make pruning permanent by removing reparameterisation masks."""
    for m in model.modules():
        if isinstance(m, (nn.Linear, nn.Conv2d)):
            try: prune.remove(m, 'weight')
            except ValueError: pass

model = nn.Sequential(nn.Linear(784, 256), nn.ReLU(), nn.Linear(256, 10))
apply_global_magnitude_pruning(model, 0.7)
remove_masks(model)
print('prune.remove() converts weight_orig + weight_mask -> weight (permanent).')
```

## Weight Distribution After Pruning

Before pruning, neural network weights follow an approximately Gaussian distribution centred near zero. After magnitude pruning, the distribution becomes bimodal: a sharp spike at exactly zero (the pruned weights) and a broader distribution of large-magnitude survivors. The bimodal signature can be detected by plotting weight histograms. The PyTorch prune API implements pruning via reparameterisation: it stores weight_orig (original values) and a binary weight_mask, computing weight = weight_orig * weight_mask on each forward pass. Calling prune.remove() collapses this into a single sparse weight tensor.

## Gradual Pruning Schedule (Zhu & Gupta 2018)

One-shot pruning — removing all target weights at once — causes a large accuracy drop that fine-tuning may not recover. Zhu & Gupta (2018) proposed gradual pruning with a polynomial schedule: s(t) = s_f + (s_i - s_f)(1 - (t-t₀)/(n·Δt))³, where t₀ is the start step, n is the number of pruning steps, and Δt is the step interval. The cubic polynomial gives a slow start (minimal early pruning), aggressive middle phase, and slow finish (fine-grained tuning at high sparsity). Pruning is applied every Δt training steps, with normal gradient updates continuing between steps so the network can redistribute information after each pruning event.

```python
import torch
import torch.nn as nn
import torch.nn.utils.prune as prune

def polynomial_sparsity(step: int, t0: int, n_steps: int, delta_t: int,
                         s_i: float = 0.0, s_f: float = 0.9) -> float:
    """
    Zhu & Gupta (2018) cubic polynomial pruning schedule.
    s(t) = s_f + (s_i - s_f) * (1 - (t - t0) / (n * delta_t))^3
    """
    if step < t0:
        return 0.0
    if step >= t0 + n_steps * delta_t:
        return s_f
    progress = (step - t0) / (n_steps * delta_t)
    return s_f + (s_i - s_f) * (1.0 - progress) ** 3

def gradual_prune_step(model: nn.Module, step: int, t0: int,
                        n_steps: int, delta_t: int, s_f: float = 0.9):
    """Apply pruning to reach the scheduled sparsity at this training step."""
    if step % delta_t != 0:
        return 0.0  # only prune at scheduled intervals
    current_s = polynomial_sparsity(step, t0, n_steps, delta_t, s_f=s_f)
    if current_s > 0:
        params = [(m, 'weight') for m in model.modules()
                   if isinstance(m, (nn.Linear, nn.Conv2d))]
        prune.global_unstructured(params, prune.L1Unstructured, amount=current_s)
    return current_s

# Visualise schedule: t0=100, n=10, delta_t=100, s_f=0.9
print(f'{"Step":>6}  {"Scheduled Sparsity":>20}')
for step in [0, 100, 200, 400, 700, 1000, 1100, 1200]:
    s = polynomial_sparsity(step, t0=100, n_steps=10, delta_t=100, s_f=0.9)
    print(f'{step:>6}  {s:>20.1%}')
```

## Prune-Retrain Cycles and Weight Recovery

Between each scheduled pruning step, the network is trained normally via backpropagation. Pruned weights receive zero gradient (they are masked), but surviving weights can grow in magnitude to compensate. This redistribution is the key mechanism behind gradual pruning's accuracy advantage: surviving weights specialise to cover the functions of the removed ones. The learning rate during gradual pruning should be 10-30% of the original training LR — too high causes instability when the mask suddenly changes, too low prevents recovery. After reaching target sparsity, a final fine-tuning phase at 1% of original LR polishes the sparse model.

## GPU Acceleration Limitations

A common misconception is that a 90% sparse model runs 10x faster. This is false for standard GPU hardware. GPU matrix multiplication is implemented as dense GEMM via cuBLAS. A weight matrix with 90% zeros still performs the full M×K×N multiply-add operations — the hardware does not skip zero multiplications. Zero weights are multiplied by activations, producing zero products that accumulate normally: wasted compute, not skipped compute. Real speedup from unstructured sparsity requires: (1) NVIDIA A100+ with N:M sparsity (50% sparsity, 2x speedup), (2) custom SpMM kernels on CPU, or (3) structured pruning that reduces matrix dimensions.

```python
import torch
import torch.nn as nn
import torch.nn.utils.prune as prune
import time

def timed_inference(model: nn.Module, x: torch.Tensor,
                     n_warmup: int = 5, n_runs: int = 30) -> float:
    """Return average inference time (ms) over n_runs forward passes."""
    model.eval()
    if x.is_cuda: torch.cuda.synchronize()
    for _ in range(n_warmup):
        with torch.no_grad(): _ = model(x)
    if x.is_cuda: torch.cuda.synchronize()
    t0 = time.perf_counter()
    for _ in range(n_runs):
        with torch.no_grad(): _ = model(x)
    if x.is_cuda: torch.cuda.synchronize()
    return (time.perf_counter() - t0) / n_runs * 1000

device = torch.device('cuda' if torch.cuda.is_available() else 'cpu')
model  = nn.Sequential(nn.Linear(1024, 2048), nn.ReLU(), nn.Linear(2048, 10)).to(device)
x      = torch.randn(64, 1024, device=device)

dense_ms = timed_inference(model, x)

params = [(m, 'weight') for m in model.modules() if isinstance(m, nn.Linear)]
prune.global_unstructured(params, prune.L1Unstructured, amount=0.9)
sparse_ms = timed_inference(model, x)

print(f'Device: {device}')
print(f'Dense model (0% sparsity):    {dense_ms:.3f} ms/batch')
print(f'Sparse model (90% sparsity):  {sparse_ms:.3f} ms/batch')
print(f'Speedup: {dense_ms/sparse_ms:.2f}x  (expected ~1.0x without hardware support)')
print('Unstructured sparsity: zeros still participate in dense matmul on standard GPU.')
print('Need N:M sparsity (A100 Sparse Tensor Cores) or structured pruning for speedup.')
```

## Accuracy vs Sparsity Curve

Empirical studies show that with gradual magnitude pruning, ResNet-20 on CIFAR-10 maintains accuracy within 1% of the baseline up to ~80% sparsity. Beyond 90%, accuracy drops steeply — the accuracy cliff. The cliff location depends on model size: larger models (ResNet-50 on ImageNet) maintain accuracy up to 95% sparsity due to higher over-parameterisation. Local pruning shifts the cliff to lower sparsity than global pruning because it cannot reallocate the budget from redundant to critical layers. Gradual pruning extends the cliff by ~5% absolute sparsity compared to one-shot pruning.

```python
import numpy as np

# ResNet-20 on CIFAR-10: accuracy under different pruning strategies
sparsity  = [0.0,  0.5,  0.7,  0.9,  0.95, 0.99]
mag_glob  = [91.8, 91.3, 90.7, 87.9, 82.1, 60.3]  # global magnitude, one-shot
mag_local = [91.8, 90.8, 89.5, 84.8, 76.5, 51.2]  # local magnitude, one-shot
gradual   = [91.8, 91.6, 91.2, 89.7, 85.4, 66.8]  # gradual schedule (Zhu & Gupta)

print(f'{"Sparsity":>10}  {"Global Mag":>12}  {"Local Mag":>11}  {"Gradual":>9}  {"Gradual Gain":>14}')
print('-' * 64)
for s, g, l, gr in zip(sparsity, mag_glob, mag_local, gradual):
    gain = gr - g
    print(f'{s:>10.0%}  {g:>12.1f}  {l:>11.1f}  {gr:>9.1f}  {gain:>+14.1f}')

baseline = mag_glob[0]
cliff_global  = next((s for s, a in zip(sparsity, mag_glob)  if baseline - a > 2), None)
cliff_gradual = next((s for s, a in zip(sparsity, gradual)   if baseline - a > 2), None)
print(f'\nAccuracy cliff (>2pp drop): global={cliff_global:.0%}  gradual={cliff_gradual:.0%}')
mean_benefit = np.mean([gr - g for gr, g in zip(gradual[1:], mag_glob[1:])])
print(f'Mean accuracy benefit of gradual over one-shot: +{mean_benefit:.1f} pp')
```

## Lottery Ticket Hypothesis Connection

Frankle & Carlin (2019) observed that within a large dense network there exist sparse subnetworks — winning tickets — that, when trained from the original weight initialisation, match the full network's accuracy. These are identified by training the full network, pruning the smallest weights, and resetting surviving weights to their initial values. Critically, the lottery ticket must be trained from the same initialisation — randomly reinitialising the surviving weights fails. Iterative magnitude pruning (IMP) is the practical algorithm: prune 20% of remaining weights per cycle, reset to original init, retrain.

> **When Unstructured Pruning Is the Right Choice**: Choose unstructured pruning when: (1) targeting a CPU with a sparse linear algebra library (MKL sparse BLAS, oneDNN), (2) you have an A100+ GPU and can use 2:4 N:M sparsity for 2x throughput, (3) experimenting with lottery tickets and need extreme sparsity (>90%) with minimal accuracy loss, or (4) model storage and memory footprint are the bottleneck rather than inference latency. For raw GPU inference speedup on standard hardware, structured pruning or INT8 quantisation are more effective choices.

| Sparsity | Accuracy (ResNet-20 CIFAR-10) | Non-Zero Params | Model Size | GPU Speedup | CPU Speedup (SpMM) |
| --- | --- | --- | --- | --- | --- |
| 0% (dense) | 91.8% | 100% | 1.0x | 1.0x | 1.0x |
| 50% | 91.3% | 50% | ~0.6x | ~1.0x (no benefit) | ~1.2x |
| 70% | 90.7% | 30% | ~0.4x | ~1.0x | ~1.8x |
| 90% | 87.9% | 10% | ~0.2x | ~1.0x | ~3.5x |
| 90% N:M (A100) | 91.2% | 50% (structured) | ~0.6x | ~2.0x | N/A |

- Global pruning concentrates sparsity in over-parameterised layers; local pruning applies a uniform ratio per layer.
- PyTorch prune API: prune.l1_unstructured for local, prune.global_unstructured for global magnitude pruning.
- prune.remove() collapses weight_orig + weight_mask into a single sparse weight tensor permanently.
- Zhu & Gupta cubic schedule: slow start, aggressive middle, slow finish — better than linear or step schedules.
- Accuracy cliff: above ~80-90% sparsity for most architectures, accuracy drops sharply with magnitude pruning.
- Lottery ticket: winning ticket subnetworks require the exact original initialisation — random reset fails.

---

