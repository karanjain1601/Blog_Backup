---
title: "Flow Matching: Continuous Normalizing Flows for Generation"
slug: "flow-matching-generative"
description: "How flow matching trains a velocity field to transport noise to data along straight paths — with fewer ODE steps than diffusion."
tags: ["flow-matching", "generative-models", "normalizing-flows", "diffusion"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Flow matching is a simulation-free framework for training continuous normalizing flows. Rather than solving an ODE during training, it directly regresses a velocity field that transports samples from Gaussian noise to the data distribution along smooth interpolated paths — making training as cheap as score matching."},{"type":"text","content":"The key insight: instead of learning to reverse a fixed noising process, flow matching learns a vector field v_t(x) such that integrating from t=0 to t=1 transforms noise into data. The path shape is a design choice — linear interpolation, optimal transport, or cosine schedules all work, each with different efficiency tradeoffs."},{"type":"callout","variant":"info","content":"Flow matching with optimal transport paths produces straighter trajectories than diffusion — meaning fewer integration steps are needed. Rectified Flow (used in SD3/Flux) iteratively straightens paths by resampling pairs along learned trajectories."},{"type":"heading","level":2,"content":"Conditional Flow Matching"},{"type":"text","content":"Conditional flow matching (CFM) constructs a per-sample probability path from noise x0 to data point x1. For a linear interpolation path, the conditional path is x_t = (1-t)*x0 + t*x1 where x0 ~ N(0,I). The conditional velocity field is simply the constant vector u_t = x1 - x0, pointing from noise to data."},{"type":"code","language":"python","content":"# Linear interpolation path and constant velocity target\nimport torch\n\ndef sample_path(x0, x1, t):\n    \"\"\"x0: noise, x1: data, t: scalar in [0,1]\"\"\"\n    x_t = (1 - t) * x0 + t * x1\n    u_t = x1 - x0  # constant for straight paths\n    return x_t, u_t\n\nx0 = torch.randn(4, 3, 64, 64)   # noise\nx1 = real_batch                   # data\nt  = torch.rand(4, 1, 1, 1)      # random timesteps\nx_t, target_v = sample_path(x0, x1, t)"},{"type":"text","content":"The velocity network v_theta(x_t, t) is trained to predict u_t. At inference, starting from x0 ~ N(0,I), integrate dx/dt = v_theta(x_t, t) from t=0 to t=1 with an ODE solver. The simplicity of the constant velocity target makes training stable from initialization — no annealing or warm-up schedules needed."},{"type":"heading","level":2,"content":"Optimal Transport Paths"},{"type":"text","content":"While any interpolation works for CFM, optimal transport (OT) paths minimize average path length. By pairing noise samples with data points that minimize expected squared distance, OT CFM produces nearly straight trajectories across the dataset — dramatically reducing the number of ODE steps needed at inference."},{"type":"text","content":"Mini-batch OT is the practical approximation: within each batch, solve the assignment problem between noise and data samples using the Sinkhorn algorithm. Rectified Flow offers an alternative — train with random pairs first, then reflow using coupled (x0, x1) pairs generated by the learned flow. Each reflow iteration straightens trajectories further."},{"type":"table","headers":["Method","Path Type","Training Loss","NFE Needed","FID (ImageNet 256)","Deterministic"],"rows":[["DDPM","Markov chain (1000 steps)","Denoising score matching","1000","~3.0","No"],["DDIM","ODE (deterministic)","Score matching","50","~4.2","Yes"],["Flow Matching (linear)","Straight-line interpolation","Velocity regression","20","~2.5","Yes"],["Flow Matching (OT)","Optimal transport path","Velocity regression (OT pairs)","10","~2.1","Yes"],["Rectified Flow","Iteratively straightened","Velocity regression (reflow)","8-15","~2.0","Yes"]]},{"type":"heading","level":2,"content":"CFM Training Objective"},{"type":"text","content":"The CFM loss is a simple mean-squared error between the network\u0027s predicted velocity and the analytic conditional target velocity. Because the target is x1 - x0 for linear paths, no score network or energy function is needed. This makes CFM strictly simpler to implement than DDPM while matching or exceeding generation quality."},{"type":"code","language":"python","content":"# CFM training loop\nimport torch, torch.nn.functional as F\n\ndef cfm_loss(velocity_net, data_batch):\n    B = data_batch.shape[0]\n    noise = torch.randn_like(data_batch)\n    t = torch.rand(B, 1, 1, 1, device=data_batch.device)\n\n    x_t = (1 - t) * noise + t * data_batch\n    target_v = data_batch - noise  # constant velocity\n\n    pred_v = velocity_net(x_t, t.squeeze())\n    return F.mse_loss(pred_v, target_v)"},{"type":"text","content":"The velocity network architecture mirrors diffusion U-Nets or DiTs. The only change is the output represents a velocity field rather than predicted noise. Most diffusion codebases can be adapted to flow matching by changing only the loss function and sampling loop — pretrained diffusion weights can even be fine-tuned with flow matching objectives."},{"type":"heading","level":2,"content":"Flow Matching vs Diffusion"},{"type":"text","content":"Diffusion learns a score function (gradient of log density) at each noise level. Flow matching learns a velocity field directly — a more direct parameterization that often converges faster and produces straighter sampling trajectories. Function evaluations (NFE) are the key efficiency metric: flow matching typically needs 8-20 vs diffusion\u0027s 50-1000."},{"type":"code","language":"python","content":"# ODE sampling with torchdiffeq\nfrom torchdiffeq import odeint\nimport torch\n\ndef velocity_fn(t, x):\n    t_batch = t.expand(x.shape[0])\n    return velocity_net(x, t_batch)\n\nx_init  = torch.randn(4, 3, 256, 256)\nt_span  = torch.linspace(0, 1, 50)\n\n# Full trajectory — final frame is the generated image\ntrajectory = odeint(velocity_fn, x_init, t_span,\n                    method=\u0027dopri5\u0027, rtol=1e-4, atol=1e-4)"},{"type":"text","content":"Adaptive ODE solvers (dopri5) automatically adjust step size for accuracy. For a fixed-NFE tradeoff, Euler integration with 10-20 steps often suffices after reflow. Guidance works identically to diffusion: classifier-free guidance applies at sampling time by interpolating conditional and unconditional velocity predictions."},{"type":"code","language":"python","content":"# NFE vs FID tradeoff benchmark\ndef measure_nfe_fid(model, steps_list, n_samples=5000):\n    results = {}\n    for nfe in steps_list:\n        t_span = torch.linspace(0, 1, nfe)\n        imgs = generate_samples(model, t_span, n_samples)\n        fid = compute_fid(imgs, real_dataset)\n        results[nfe] = fid\n        print(f\"NFE={nfe}: FID={fid:.2f}\")\n    return results\n\nnfe_list     = [5, 10, 20, 50, 100]\nflow_results = measure_nfe_fid(flow_model, nfe_list)\ndiff_results = measure_nfe_fid(ddim_model, nfe_list)"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Flow matching is now the dominant paradigm for state-of-the-art text-to-image models. Stable Diffusion 3 and Flux both use Rectified Flow with multi-modal DiT architectures. Training simplicity (MSE loss, analytic targets) and sampling efficiency (few ODE steps) make it strictly superior to DDPM/DDIM for most practical use cases."},{"type":"text","content":"For practitioners with existing diffusion codebases: switching to flow matching requires only changing the loss (predict velocity instead of noise) and updating the sampling loop to use an ODE integrator. The generalization beyond images is substantial — flow matching is now used for protein structure, molecular dynamics, video, and audio generation."},{"type":"text","content":"Rectified Flow\u0027s iterative reflow procedure is particularly powerful: one reflow iteration typically halves the NFE needed for the same FID, and two iterations can approach optimal straight-line paths. This post-training refinement works on any trained flow model without access to the original training data."}]"
---
# Flow Matching: Continuous Normalizing Flows for Generation

## Overview

Flow matching is a simulation-free framework for training continuous normalizing flows. Rather than solving an ODE during training, it directly regresses a velocity field that transports samples from Gaussian noise to the data distribution along smooth interpolated paths — making training as cheap as score matching.

The key insight: instead of learning to reverse a fixed noising process, flow matching learns a vector field v_t(x) such that integrating from t=0 to t=1 transforms noise into data. The path shape is a design choice — linear interpolation, optimal transport, or cosine schedules all work, each with different efficiency tradeoffs.

> **info**: Flow matching with optimal transport paths produces straighter trajectories than diffusion — meaning fewer integration steps are needed. Rectified Flow (used in SD3/Flux) iteratively straightens paths by resampling pairs along learned trajectories.

## Conditional Flow Matching

Conditional flow matching (CFM) constructs a per-sample probability path from noise x0 to data point x1. For a linear interpolation path, the conditional path is x_t = (1-t)*x0 + t*x1 where x0 ~ N(0,I). The conditional velocity field is simply the constant vector u_t = x1 - x0, pointing from noise to data.

```python
# Linear interpolation path and constant velocity target
import torch

def sample_path(x0, x1, t):
    """x0: noise, x1: data, t: scalar in [0,1]"""
    x_t = (1 - t) * x0 + t * x1
    u_t = x1 - x0  # constant for straight paths
    return x_t, u_t

x0 = torch.randn(4, 3, 64, 64)   # noise
x1 = real_batch                   # data
t  = torch.rand(4, 1, 1, 1)      # random timesteps
x_t, target_v = sample_path(x0, x1, t)
```

The velocity network v_theta(x_t, t) is trained to predict u_t. At inference, starting from x0 ~ N(0,I), integrate dx/dt = v_theta(x_t, t) from t=0 to t=1 with an ODE solver. The simplicity of the constant velocity target makes training stable from initialization — no annealing or warm-up schedules needed.

## Optimal Transport Paths

While any interpolation works for CFM, optimal transport (OT) paths minimize average path length. By pairing noise samples with data points that minimize expected squared distance, OT CFM produces nearly straight trajectories across the dataset — dramatically reducing the number of ODE steps needed at inference.

Mini-batch OT is the practical approximation: within each batch, solve the assignment problem between noise and data samples using the Sinkhorn algorithm. Rectified Flow offers an alternative — train with random pairs first, then reflow using coupled (x0, x1) pairs generated by the learned flow. Each reflow iteration straightens trajectories further.

| Method | Path Type | Training Loss | NFE Needed | FID (ImageNet 256) | Deterministic |
| --- | --- | --- | --- | --- | --- |
| DDPM | Markov chain (1000 steps) | Denoising score matching | 1000 | ~3.0 | No |
| DDIM | ODE (deterministic) | Score matching | 50 | ~4.2 | Yes |
| Flow Matching (linear) | Straight-line interpolation | Velocity regression | 20 | ~2.5 | Yes |
| Flow Matching (OT) | Optimal transport path | Velocity regression (OT pairs) | 10 | ~2.1 | Yes |
| Rectified Flow | Iteratively straightened | Velocity regression (reflow) | 8-15 | ~2.0 | Yes |

## CFM Training Objective

The CFM loss is a simple mean-squared error between the network's predicted velocity and the analytic conditional target velocity. Because the target is x1 - x0 for linear paths, no score network or energy function is needed. This makes CFM strictly simpler to implement than DDPM while matching or exceeding generation quality.

```python
# CFM training loop
import torch, torch.nn.functional as F

def cfm_loss(velocity_net, data_batch):
    B = data_batch.shape[0]
    noise = torch.randn_like(data_batch)
    t = torch.rand(B, 1, 1, 1, device=data_batch.device)

    x_t = (1 - t) * noise + t * data_batch
    target_v = data_batch - noise  # constant velocity

    pred_v = velocity_net(x_t, t.squeeze())
    return F.mse_loss(pred_v, target_v)
```

The velocity network architecture mirrors diffusion U-Nets or DiTs. The only change is the output represents a velocity field rather than predicted noise. Most diffusion codebases can be adapted to flow matching by changing only the loss function and sampling loop — pretrained diffusion weights can even be fine-tuned with flow matching objectives.

## Flow Matching vs Diffusion

Diffusion learns a score function (gradient of log density) at each noise level. Flow matching learns a velocity field directly — a more direct parameterization that often converges faster and produces straighter sampling trajectories. Function evaluations (NFE) are the key efficiency metric: flow matching typically needs 8-20 vs diffusion's 50-1000.

```python
# ODE sampling with torchdiffeq
from torchdiffeq import odeint
import torch

def velocity_fn(t, x):
    t_batch = t.expand(x.shape[0])
    return velocity_net(x, t_batch)

x_init  = torch.randn(4, 3, 256, 256)
t_span  = torch.linspace(0, 1, 50)

# Full trajectory — final frame is the generated image
trajectory = odeint(velocity_fn, x_init, t_span,
                    method='dopri5', rtol=1e-4, atol=1e-4)
```

Adaptive ODE solvers (dopri5) automatically adjust step size for accuracy. For a fixed-NFE tradeoff, Euler integration with 10-20 steps often suffices after reflow. Guidance works identically to diffusion: classifier-free guidance applies at sampling time by interpolating conditional and unconditional velocity predictions.

```python
# NFE vs FID tradeoff benchmark
def measure_nfe_fid(model, steps_list, n_samples=5000):
    results = {}
    for nfe in steps_list:
        t_span = torch.linspace(0, 1, nfe)
        imgs = generate_samples(model, t_span, n_samples)
        fid = compute_fid(imgs, real_dataset)
        results[nfe] = fid
        print(f"NFE={nfe}: FID={fid:.2f}")
    return results

nfe_list     = [5, 10, 20, 50, 100]
flow_results = measure_nfe_fid(flow_model, nfe_list)
diff_results = measure_nfe_fid(ddim_model, nfe_list)
```

## Key Takeaways

Flow matching is now the dominant paradigm for state-of-the-art text-to-image models. Stable Diffusion 3 and Flux both use Rectified Flow with multi-modal DiT architectures. Training simplicity (MSE loss, analytic targets) and sampling efficiency (few ODE steps) make it strictly superior to DDPM/DDIM for most practical use cases.

For practitioners with existing diffusion codebases: switching to flow matching requires only changing the loss (predict velocity instead of noise) and updating the sampling loop to use an ODE integrator. The generalization beyond images is substantial — flow matching is now used for protein structure, molecular dynamics, video, and audio generation.

Rectified Flow's iterative reflow procedure is particularly powerful: one reflow iteration typically halves the NFE needed for the same FID, and two iterations can approach optimal straight-line paths. This post-training refinement works on any trained flow model without access to the original training data.

