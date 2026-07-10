---
title: "Data-Free Knowledge Distillation — Synthesizing Proxy Data"
slug: "data-free-distillation"
description: "Data-free KD synthesises proxy training data using only the trained teacher model, enabling distillation without access to the original dataset. Covers activation maximisation, BN statistic regularisation, DAFL generator methods, CMI, privacy use cases, and the accuracy gap vs data-dependent KD."
tags: ["deep-learning", "model-compression", "knowledge-distillation", "pruning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Standard knowledge distillation requires the same training data used to train the teacher. When that data is unavailable — due to privacy regulations, proprietary licensing, or simply being discarded after training — distillation cannot proceed. Data-free knowledge distillation (DFKD) solves this by synthesising proxy training data using only the trained teacher model itself. The frozen teacher becomes a supervisory oracle: it can label any synthetic input, and its internal BatchNorm statistics reveal properties of the original training distribution."},{"type":"heading","level":2,"content":"The Data Access Problem in Standard KD"},{"type":"text","content":"Standard KD transfers knowledge by computing KL divergence between teacher and student outputs on real training data. Without this data, there are no inputs to compute soft targets from. DFKD reframes the problem: generate synthetic inputs that the teacher responds to meaningfully. The teacher\u0027s BatchNorm running statistics — stored means and variances at every layer — encode aggregate information about the real training distribution. These statistics become the anchor for generating realistic synthetic images without any real data access."},{"type":"heading","level":2,"content":"Activation Maximization"},{"type":"text","content":"Activation maximisation is the simplest DFKD approach: optimise a synthetic image z directly in pixel space to maximise the teacher\u0027s confidence for a target class. The objective is z* = argmax_z [log p_teacher(y=c|z)]. Without regularisation, this produces adversarial-like images — high-frequency patterns that maximise neuron activations but look nothing like real data. BatchNorm statistics matching is the key regulariser: penalise synthetic images whose intermediate activations deviate from the teacher\u0027s stored running statistics. This forces generated images to produce realistic internal representations."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport torch.optim as optim\n\ndef activation_maximization(teacher: nn.Module, target_class: int,\n                             n_steps: int = 300, lr: float = 0.1,\n                             bn_reg: float = 0.001,\n                             img_shape: tuple = (1, 3, 32, 32)) -\u003e torch.Tensor:\n    \"\"\"Synthesise image by maximising teacher class probability + BN regularisation.\"\"\"\n    teacher.eval()\n    z = torch.randn(*img_shape, requires_grad=True)\n    optimizer = optim.Adam([z], lr=lr)\n    bn_hooks = []\n    for module in teacher.modules():\n        if isinstance(module, nn.BatchNorm2d):\n            mu  = module.running_mean.detach()\n            var = module.running_var.detach()\n            def make_hook(target_mu, target_var):\n                def hook(m, inp, out):\n                    m._bn_loss = (F.mse_loss(out.mean((0, 2, 3)), target_mu) +\n                                  F.mse_loss(out.var((0, 2, 3)),  target_var))\n                return hook\n            bn_hooks.append(module.register_forward_hook(make_hook(mu, var)))\n    for step in range(n_steps):\n        optimizer.zero_grad()\n        out = teacher(z)\n        cls_loss = -F.log_softmax(out, dim=-1)[0, target_class]\n        bn_loss  = sum(m._bn_loss for m in teacher.modules()\n                       if isinstance(m, nn.BatchNorm2d) and hasattr(m, \u0027_bn_loss\u0027))\n        (cls_loss + bn_reg * bn_loss).backward()\n        optimizer.step()\n    for h in bn_hooks:\n        h.remove()\n    return z.detach()\n\nprint(\u0027Activation maximisation synthesises class-conditional images from teacher only.\u0027)\nprint(\u0027BN regularisation ensures generated images have realistic activation statistics.\u0027)"},{"type":"heading","level":2,"content":"BatchNorm Statistic Regularization"},{"type":"text","content":"Every BatchNorm2d layer stores running_mean and running_var computed over the training data during training. For a synthetic image to produce realistic intermediate activations, its activations at each BN layer should match these stored statistics. The BN statistics loss is: L_BN = sum_l [MSE(mean_generated_l, mean_running_l) + MSE(var_generated_l, var_running_l)]. This loss is differentiable with respect to the input image z and can be backpropagated through the frozen teacher to shape the generated image. BN matching is what distinguishes good DFKD from naive activation maximisation."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nfrom typing import List, Tuple\n\ndef get_teacher_bn_stats(teacher: nn.Module) -\u003e List[Tuple[torch.Tensor, torch.Tensor]]:\n    \"\"\"Return (running_mean, running_var) for every BatchNorm2d in teacher.\"\"\"\n    return [(m.running_mean.detach().clone(), m.running_var.detach().clone())\n            for m in teacher.modules() if isinstance(m, nn.BatchNorm2d)]\n\ndef bn_stat_matching_loss(teacher: nn.Module, x: torch.Tensor,\n                           target_stats: List[Tuple[torch.Tensor, torch.Tensor]]) -\u003e torch.Tensor:\n    \"\"\"Penalise mismatch between x\u0027s BN activation stats and teacher\u0027s stored stats.\"\"\"\n    losses, hooks = [], []\n    bn_modules = [m for m in teacher.modules() if isinstance(m, nn.BatchNorm2d)]\n    for i, module in enumerate(bn_modules):\n        t_mean, t_var = target_stats[i]\n        def make_hook(tm, tv):\n            def hook(m, inp, out):\n                losses.append(F.mse_loss(out.mean((0, 2, 3)), tm) +\n                               F.mse_loss(out.var((0, 2, 3)),  tv))\n            return hook\n        hooks.append(module.register_forward_hook(make_hook(t_mean, t_var)))\n    teacher.eval()\n    _ = teacher(x)\n    for h in hooks:\n        h.remove()\n    return torch.stack(losses).mean() if losses else x.new_tensor(0.0)\n\nteacher = nn.Sequential(nn.Conv2d(3, 16, 3, padding=1), nn.BatchNorm2d(16), nn.ReLU(),\n                         nn.Conv2d(16, 8, 3, padding=1), nn.BatchNorm2d(8), nn.ReLU())\nreal_stats = get_teacher_bn_stats(teacher)\ngen_image  = torch.randn(4, 3, 32, 32, requires_grad=True)\nloss = bn_stat_matching_loss(teacher, gen_image, real_stats)\nprint(f\u0027BN stat matching loss (random image): {loss.item():.4f}\u0027)\nprint(\u0027Minimising this loss during synthesis yields realistic internal activations.\u0027)"},{"type":"heading","level":2,"content":"Generator-Based Methods — DAFL and CMI"},{"type":"text","content":"DAFL (Data-Free Learning of Student Networks, Chen et al. 2019) replaces per-image optimisation with a learned generator G. G takes a noise vector z and produces synthetic images x_gen = G(z). G is trained adversarially: produce images that maximise teacher confidence and activation magnitudes while maintaining diversity. The student S is simultaneously trained to match teacher outputs on generated data. CMI (Contrastive Model Inversion, Fang et al. 2022) improves diversity by adding a contrastive loss that encourages different samples to produce distinct activation patterns, reducing mode collapse in the generated distribution."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\nimport torch.nn.functional as F\n\nclass DataFreeGenerator(nn.Module):\n    def __init__(self, z_dim=100, channels=3, size=32):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(z_dim, 512), nn.BatchNorm1d(512), nn.ReLU(),\n            nn.Linear(512, channels * size * size), nn.Tanh())\n        self.out_shape = (channels, size, size)\n\n    def forward(self, z):\n        return self.net(z).view(z.size(0), *self.out_shape)\n\ndef train_dfkd(teacher, student, generator, n_steps=100, z_dim=100, B=32, T=4.0):\n    \"\"\"Data-free KD: jointly train generator + student using frozen teacher.\"\"\"\n    teacher.eval()\n    opt_g = optim.Adam(generator.parameters(), lr=1e-3)\n    opt_s = optim.Adam(student.parameters(),   lr=1e-3)\n    for step in range(n_steps):\n        z = torch.randn(B, z_dim)\n        with torch.no_grad():\n            soft = F.softmax(teacher(generator(z)) / T, dim=-1)\n        opt_s.zero_grad()\n        kd = F.kl_div(F.log_softmax(student(generator(z).detach()) / T, dim=-1),\n                       soft, reduction=\u0027batchmean\u0027) * T ** 2\n        kd.backward(); opt_s.step()\n        opt_g.zero_grad()\n        g_loss = -teacher(generator(torch.randn(B, z_dim))).softmax(-1).max(-1).values.mean()\n        g_loss.backward(); opt_g.step()\n        if (step + 1) % 25 == 0:\n            print(f\u0027Step {step+1}: KD={kd.item():.3f}  G={g_loss.item():.3f}\u0027)\n\nteacher = nn.Sequential(nn.Flatten(), nn.Linear(3072, 10))\nstudent = nn.Sequential(nn.Flatten(), nn.Linear(3072, 10))\ngen = DataFreeGenerator()\ntrain_dfkd(teacher, student, gen, n_steps=50)"},{"type":"heading","level":2,"content":"Privacy and GDPR Use Cases"},{"type":"text","content":"One compelling motivation for DFKD is privacy preservation. Training data often contains personal information — medical records, user communications, private images — that cannot be shared or stored after training under GDPR Article 17 (right to erasure). Once a model is trained, the original data can be legally deleted, leaving only the model weights. DFKD allows knowledge transfer from the frozen teacher to a smaller student without ever accessing the deleted data, enabling model compression and deployment optimisation while maintaining full regulatory compliance."},{"type":"heading","level":2,"content":"Accuracy Gap vs Data-Dependent KD"},{"type":"text","content":"Data-free KD consistently underperforms data-dependent KD. At low compression (retaining \u003e75% of teacher parameters), the gap is 1-2%. At aggressive compression (\u003c25% of parameters), the gap widens to 4-8%. CMI achieves the smallest gap by maximising mutual information between generated samples. The fundamental bottleneck is distribution shift: even the best generators do not perfectly replicate the training distribution, so the student sees a slightly different distribution than the teacher was optimised for."},{"type":"code","language":"python","content":"import numpy as np\n\n# Accuracy comparison: data-free KD methods vs data-dependent KD on CIFAR-100\n# Teacher: ResNet-34 (77.8%), Student: ResNet-18 family at various compressions\ncompression_pct = [100, 75, 50, 25, 10]  # student param % relative to teacher\n\ndata_dependent = [77.8, 76.4, 75.1, 71.3, 63.2]  # standard KD with real data\ndfkd_dafl      = [77.8, 73.8, 72.1, 67.4, 58.1]  # DAFL (Chen et al. 2019)\ndfkd_cmi       = [77.8, 74.9, 73.2, 69.1, 60.8]  # CMI  (Fang et al. 2022)\ndfkd_zeroshot  = [77.8, 72.1, 70.4, 65.2, 55.7]  # Zero-shot KD (Nayak 2019)\n\nprint(f\u0027{\"Compression\":\u003e12}  {\"Data-Dep\":\u003e9}  {\"DAFL\":\u003e7}  {\"CMI\":\u003e7}  {\"ZeroShot\":\u003e9}\u0027)\nprint(f\u0027{\"(% params)\":\u003e12}  {\"(real)\": \u003e9}  {\"(DFKD)\":\u003e7}  {\"(DFKD)\":\u003e7}  {\"(DFKD)\":\u003e9}\u0027)\nprint(\u0027-\u0027 * 55)\nfor c, dd, da, cm, zs in zip(compression_pct, data_dependent, dfkd_dafl, dfkd_cmi, dfkd_zeroshot):\n    print(f\u0027{c:\u003e11}%  {dd:\u003e9.1f}  {da:\u003e7.1f}  {cm:\u003e7.1f}  {zs:\u003e9.1f}\u0027)\n\ngaps_dafl = [dd - da for dd, da in zip(data_dependent, dfkd_dafl)]\ngaps_cmi  = [dd - cm for dd, cm in zip(data_dependent, dfkd_cmi)]\nprint(f\u0027\\nMean accuracy gap — DAFL: {np.mean(gaps_dafl):.1f}%  CMI: {np.mean(gaps_cmi):.1f}%\u0027)\nprint(f\u0027Typical data-free quality gap: 2-5% vs data-dependent KD.\u0027)"},{"type":"heading","level":2,"content":"Fast-DFKD and Amortized Generation"},{"type":"text","content":"Fast-DFKD (Fang et al. 2021) reduces the computational cost of DFKD through meta-learning. Rather than training a new generator from scratch for each teacher model, Fast-DFKD meta-learns a generator initialisation that adapts quickly to any teacher with only a few gradient steps. The meta-learned initialisation captures general visual priors (edges, textures, shapes) that are useful for any classification teacher, requiring only task-specific fine-tuning. Zero-shot KD (Nayak et al. 2019) is another fast approach: it samples from a Dirichlet distribution conditioned on the teacher\u0027s class statistics, bypassing neural synthesis entirely at lower accuracy."},{"type":"callout","variant":"warning","title":"Data-Free KD Cannot Fully Recover Data-Dependent KD Accuracy","content":"The 2-5% accuracy gap between data-free and data-dependent KD is a fundamental information-theoretic limitation. The teacher weights encode information about training data, but not all of it. Generated images can match BN statistics globally but not capture rare examples, class boundaries, or domain-specific patterns. If accuracy recovery is critical, consider using even a small amount of real data — 100 samples per class — to anchor the synthesis. This dramatically closes the gap at minimal privacy cost."},{"type":"table","headers":["Method","Data Required","Generator Type","Accuracy vs Real KD","Privacy Safe","Training Cost"],"rows":[["Activation maximisation","None","Per-image optimisation","-4 to -8%","Yes","High (per-image opt)"],["DAFL (Chen 2019)","None","GAN generator","-3 to -5%","Yes","Medium (train G once)"],["CMI (Fang 2022)","None","GAN + contrastive","-2 to -4%","Yes","Medium"],["Zero-shot KD (Nayak 2019)","None","Dirichlet sampling","-4 to -7%","Yes","Low (no generator)"],["Fast-DFKD","None","Meta-learned generator","-3 to -5%","Yes","Low (fast adaptation)"],["Data-dependent KD","Full training set","Real data","Baseline","No","Low (no generator)"]]},{"type":"list","ordered":false,"items":["BN statistic matching is the key regulariser: without it, generated images are adversarial-like noise.","Temperature for DFKD generator training: use T=20 (very soft) to maximise gradient signal.","Generator diversity: condition G on one-hot class labels for class-conditional image synthesis.","DAFL objective: maximise teacher confidence + activation magnitude + sample diversity (three terms).","GDPR compliance: DFKD allows legal model compression when training data must be deleted post-training.","Quality gap closes with data: 100 real samples per class reduces the gap by ~50% vs fully data-free."]},{"type":"divider"}]"
---
# Data-Free Knowledge Distillation — Synthesizing Proxy Data

Standard knowledge distillation requires the same training data used to train the teacher. When that data is unavailable — due to privacy regulations, proprietary licensing, or simply being discarded after training — distillation cannot proceed. Data-free knowledge distillation (DFKD) solves this by synthesising proxy training data using only the trained teacher model itself. The frozen teacher becomes a supervisory oracle: it can label any synthetic input, and its internal BatchNorm statistics reveal properties of the original training distribution.

## The Data Access Problem in Standard KD

Standard KD transfers knowledge by computing KL divergence between teacher and student outputs on real training data. Without this data, there are no inputs to compute soft targets from. DFKD reframes the problem: generate synthetic inputs that the teacher responds to meaningfully. The teacher's BatchNorm running statistics — stored means and variances at every layer — encode aggregate information about the real training distribution. These statistics become the anchor for generating realistic synthetic images without any real data access.

## Activation Maximization

Activation maximisation is the simplest DFKD approach: optimise a synthetic image z directly in pixel space to maximise the teacher's confidence for a target class. The objective is z* = argmax_z [log p_teacher(y=c|z)]. Without regularisation, this produces adversarial-like images — high-frequency patterns that maximise neuron activations but look nothing like real data. BatchNorm statistics matching is the key regulariser: penalise synthetic images whose intermediate activations deviate from the teacher's stored running statistics. This forces generated images to produce realistic internal representations.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import torch.optim as optim

def activation_maximization(teacher: nn.Module, target_class: int,
                             n_steps: int = 300, lr: float = 0.1,
                             bn_reg: float = 0.001,
                             img_shape: tuple = (1, 3, 32, 32)) -> torch.Tensor:
    """Synthesise image by maximising teacher class probability + BN regularisation."""
    teacher.eval()
    z = torch.randn(*img_shape, requires_grad=True)
    optimizer = optim.Adam([z], lr=lr)
    bn_hooks = []
    for module in teacher.modules():
        if isinstance(module, nn.BatchNorm2d):
            mu  = module.running_mean.detach()
            var = module.running_var.detach()
            def make_hook(target_mu, target_var):
                def hook(m, inp, out):
                    m._bn_loss = (F.mse_loss(out.mean((0, 2, 3)), target_mu) +
                                  F.mse_loss(out.var((0, 2, 3)),  target_var))
                return hook
            bn_hooks.append(module.register_forward_hook(make_hook(mu, var)))
    for step in range(n_steps):
        optimizer.zero_grad()
        out = teacher(z)
        cls_loss = -F.log_softmax(out, dim=-1)[0, target_class]
        bn_loss  = sum(m._bn_loss for m in teacher.modules()
                       if isinstance(m, nn.BatchNorm2d) and hasattr(m, '_bn_loss'))
        (cls_loss + bn_reg * bn_loss).backward()
        optimizer.step()
    for h in bn_hooks:
        h.remove()
    return z.detach()

print('Activation maximisation synthesises class-conditional images from teacher only.')
print('BN regularisation ensures generated images have realistic activation statistics.')
```

## BatchNorm Statistic Regularization

Every BatchNorm2d layer stores running_mean and running_var computed over the training data during training. For a synthetic image to produce realistic intermediate activations, its activations at each BN layer should match these stored statistics. The BN statistics loss is: L_BN = sum_l [MSE(mean_generated_l, mean_running_l) + MSE(var_generated_l, var_running_l)]. This loss is differentiable with respect to the input image z and can be backpropagated through the frozen teacher to shape the generated image. BN matching is what distinguishes good DFKD from naive activation maximisation.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
from typing import List, Tuple

def get_teacher_bn_stats(teacher: nn.Module) -> List[Tuple[torch.Tensor, torch.Tensor]]:
    """Return (running_mean, running_var) for every BatchNorm2d in teacher."""
    return [(m.running_mean.detach().clone(), m.running_var.detach().clone())
            for m in teacher.modules() if isinstance(m, nn.BatchNorm2d)]

def bn_stat_matching_loss(teacher: nn.Module, x: torch.Tensor,
                           target_stats: List[Tuple[torch.Tensor, torch.Tensor]]) -> torch.Tensor:
    """Penalise mismatch between x's BN activation stats and teacher's stored stats."""
    losses, hooks = [], []
    bn_modules = [m for m in teacher.modules() if isinstance(m, nn.BatchNorm2d)]
    for i, module in enumerate(bn_modules):
        t_mean, t_var = target_stats[i]
        def make_hook(tm, tv):
            def hook(m, inp, out):
                losses.append(F.mse_loss(out.mean((0, 2, 3)), tm) +
                               F.mse_loss(out.var((0, 2, 3)),  tv))
            return hook
        hooks.append(module.register_forward_hook(make_hook(t_mean, t_var)))
    teacher.eval()
    _ = teacher(x)
    for h in hooks:
        h.remove()
    return torch.stack(losses).mean() if losses else x.new_tensor(0.0)

teacher = nn.Sequential(nn.Conv2d(3, 16, 3, padding=1), nn.BatchNorm2d(16), nn.ReLU(),
                         nn.Conv2d(16, 8, 3, padding=1), nn.BatchNorm2d(8), nn.ReLU())
real_stats = get_teacher_bn_stats(teacher)
gen_image  = torch.randn(4, 3, 32, 32, requires_grad=True)
loss = bn_stat_matching_loss(teacher, gen_image, real_stats)
print(f'BN stat matching loss (random image): {loss.item():.4f}')
print('Minimising this loss during synthesis yields realistic internal activations.')
```

## Generator-Based Methods — DAFL and CMI

DAFL (Data-Free Learning of Student Networks, Chen et al. 2019) replaces per-image optimisation with a learned generator G. G takes a noise vector z and produces synthetic images x_gen = G(z). G is trained adversarially: produce images that maximise teacher confidence and activation magnitudes while maintaining diversity. The student S is simultaneously trained to match teacher outputs on generated data. CMI (Contrastive Model Inversion, Fang et al. 2022) improves diversity by adding a contrastive loss that encourages different samples to produce distinct activation patterns, reducing mode collapse in the generated distribution.

```python
import torch
import torch.nn as nn
import torch.optim as optim
import torch.nn.functional as F

class DataFreeGenerator(nn.Module):
    def __init__(self, z_dim=100, channels=3, size=32):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(z_dim, 512), nn.BatchNorm1d(512), nn.ReLU(),
            nn.Linear(512, channels * size * size), nn.Tanh())
        self.out_shape = (channels, size, size)

    def forward(self, z):
        return self.net(z).view(z.size(0), *self.out_shape)

def train_dfkd(teacher, student, generator, n_steps=100, z_dim=100, B=32, T=4.0):
    """Data-free KD: jointly train generator + student using frozen teacher."""
    teacher.eval()
    opt_g = optim.Adam(generator.parameters(), lr=1e-3)
    opt_s = optim.Adam(student.parameters(),   lr=1e-3)
    for step in range(n_steps):
        z = torch.randn(B, z_dim)
        with torch.no_grad():
            soft = F.softmax(teacher(generator(z)) / T, dim=-1)
        opt_s.zero_grad()
        kd = F.kl_div(F.log_softmax(student(generator(z).detach()) / T, dim=-1),
                       soft, reduction='batchmean') * T ** 2
        kd.backward(); opt_s.step()
        opt_g.zero_grad()
        g_loss = -teacher(generator(torch.randn(B, z_dim))).softmax(-1).max(-1).values.mean()
        g_loss.backward(); opt_g.step()
        if (step + 1) % 25 == 0:
            print(f'Step {step+1}: KD={kd.item():.3f}  G={g_loss.item():.3f}')

teacher = nn.Sequential(nn.Flatten(), nn.Linear(3072, 10))
student = nn.Sequential(nn.Flatten(), nn.Linear(3072, 10))
gen = DataFreeGenerator()
train_dfkd(teacher, student, gen, n_steps=50)
```

## Privacy and GDPR Use Cases

One compelling motivation for DFKD is privacy preservation. Training data often contains personal information — medical records, user communications, private images — that cannot be shared or stored after training under GDPR Article 17 (right to erasure). Once a model is trained, the original data can be legally deleted, leaving only the model weights. DFKD allows knowledge transfer from the frozen teacher to a smaller student without ever accessing the deleted data, enabling model compression and deployment optimisation while maintaining full regulatory compliance.

## Accuracy Gap vs Data-Dependent KD

Data-free KD consistently underperforms data-dependent KD. At low compression (retaining >75% of teacher parameters), the gap is 1-2%. At aggressive compression (<25% of parameters), the gap widens to 4-8%. CMI achieves the smallest gap by maximising mutual information between generated samples. The fundamental bottleneck is distribution shift: even the best generators do not perfectly replicate the training distribution, so the student sees a slightly different distribution than the teacher was optimised for.

```python
import numpy as np

# Accuracy comparison: data-free KD methods vs data-dependent KD on CIFAR-100
# Teacher: ResNet-34 (77.8%), Student: ResNet-18 family at various compressions
compression_pct = [100, 75, 50, 25, 10]  # student param % relative to teacher

data_dependent = [77.8, 76.4, 75.1, 71.3, 63.2]  # standard KD with real data
dfkd_dafl      = [77.8, 73.8, 72.1, 67.4, 58.1]  # DAFL (Chen et al. 2019)
dfkd_cmi       = [77.8, 74.9, 73.2, 69.1, 60.8]  # CMI  (Fang et al. 2022)
dfkd_zeroshot  = [77.8, 72.1, 70.4, 65.2, 55.7]  # Zero-shot KD (Nayak 2019)

print(f'{"Compression":>12}  {"Data-Dep":>9}  {"DAFL":>7}  {"CMI":>7}  {"ZeroShot":>9}')
print(f'{"(% params)":>12}  {"(real)": >9}  {"(DFKD)":>7}  {"(DFKD)":>7}  {"(DFKD)":>9}')
print('-' * 55)
for c, dd, da, cm, zs in zip(compression_pct, data_dependent, dfkd_dafl, dfkd_cmi, dfkd_zeroshot):
    print(f'{c:>11}%  {dd:>9.1f}  {da:>7.1f}  {cm:>7.1f}  {zs:>9.1f}')

gaps_dafl = [dd - da for dd, da in zip(data_dependent, dfkd_dafl)]
gaps_cmi  = [dd - cm for dd, cm in zip(data_dependent, dfkd_cmi)]
print(f'\nMean accuracy gap — DAFL: {np.mean(gaps_dafl):.1f}%  CMI: {np.mean(gaps_cmi):.1f}%')
print(f'Typical data-free quality gap: 2-5% vs data-dependent KD.')
```

## Fast-DFKD and Amortized Generation

Fast-DFKD (Fang et al. 2021) reduces the computational cost of DFKD through meta-learning. Rather than training a new generator from scratch for each teacher model, Fast-DFKD meta-learns a generator initialisation that adapts quickly to any teacher with only a few gradient steps. The meta-learned initialisation captures general visual priors (edges, textures, shapes) that are useful for any classification teacher, requiring only task-specific fine-tuning. Zero-shot KD (Nayak et al. 2019) is another fast approach: it samples from a Dirichlet distribution conditioned on the teacher's class statistics, bypassing neural synthesis entirely at lower accuracy.

> **Data-Free KD Cannot Fully Recover Data-Dependent KD Accuracy**: The 2-5% accuracy gap between data-free and data-dependent KD is a fundamental information-theoretic limitation. The teacher weights encode information about training data, but not all of it. Generated images can match BN statistics globally but not capture rare examples, class boundaries, or domain-specific patterns. If accuracy recovery is critical, consider using even a small amount of real data — 100 samples per class — to anchor the synthesis. This dramatically closes the gap at minimal privacy cost.

| Method | Data Required | Generator Type | Accuracy vs Real KD | Privacy Safe | Training Cost |
| --- | --- | --- | --- | --- | --- |
| Activation maximisation | None | Per-image optimisation | -4 to -8% | Yes | High (per-image opt) |
| DAFL (Chen 2019) | None | GAN generator | -3 to -5% | Yes | Medium (train G once) |
| CMI (Fang 2022) | None | GAN + contrastive | -2 to -4% | Yes | Medium |
| Zero-shot KD (Nayak 2019) | None | Dirichlet sampling | -4 to -7% | Yes | Low (no generator) |
| Fast-DFKD | None | Meta-learned generator | -3 to -5% | Yes | Low (fast adaptation) |
| Data-dependent KD | Full training set | Real data | Baseline | No | Low (no generator) |

- BN statistic matching is the key regulariser: without it, generated images are adversarial-like noise.
- Temperature for DFKD generator training: use T=20 (very soft) to maximise gradient signal.
- Generator diversity: condition G on one-hot class labels for class-conditional image synthesis.
- DAFL objective: maximise teacher confidence + activation magnitude + sample diversity (three terms).
- GDPR compliance: DFKD allows legal model compression when training data must be deleted post-training.
- Quality gap closes with data: 100 real samples per class reduces the gap by ~50% vs fully data-free.

---

