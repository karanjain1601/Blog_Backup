---
title: "SimSiam — Collapsing Without Negatives or Momentum"
slug: "simsiam-stop-gradient"
description: "SimSiam (Chen & He 2020) achieves self-supervised learning without negatives, EMA, or large batch sizes by applying a stop-gradient on one branch of the loss, which can be interpreted as an expectation-maximisation procedure with the predictor as the E-step."
tags: ["deep-learning", "self-supervised-learning", "contrastive-learning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"SimSiam (Simple Siamese Networks, Chen \u0026 He 2020) strips BYOL down to its minimum: no negatives, no EMA, no large batch size. The only ingredient preventing collapse is the stop-gradient operation on one branch. Despite its simplicity, SimSiam achieves competitive performance (71.3% top-1 on ImageNet with ResNet-50) and provides valuable theoretical insight into why self-supervised learning without negatives can work through an expectation-maximisation lens."},{"type":"heading","level":2,"content":"Architecture — Encoder, Projector, Predictor"},{"type":"text","content":"SimSiam uses a symmetric Siamese architecture with one asymmetric element. Both branches share the same encoder f (ResNet) and projector h (3-layer MLP with BN). On top of one branch, a two-layer MLP predictor p is applied. The key insight: the predictor is applied only to one side; the other side is stop-gradiented. There is no separate target network, no queue, no EMA — both branches share weights."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport torchvision.models as models\n\nclass SimSiam(nn.Module):\n    \"\"\"SimSiam: shared encoder + projector, asymmetric predictor + stop-gradient.\"\"\"\n    def __init__(self, backbone_fn=models.resnet50, proj_dim=2048, pred_hidden=512):\n        super().__init__()\n        base = backbone_fn(weights=None)\n        feat_dim = base.fc.in_features  # 2048\n        # Encoder (backbone without final fc)\n        self.encoder = nn.Sequential(*list(base.children())[:-1])\n        # Projector: 3-layer MLP with BN (dim stays 2048)\n        self.projector = nn.Sequential(\n            nn.Linear(feat_dim, feat_dim, bias=False),\n            nn.BatchNorm1d(feat_dim), nn.ReLU(inplace=True),\n            nn.Linear(feat_dim, feat_dim, bias=False),\n            nn.BatchNorm1d(feat_dim), nn.ReLU(inplace=True),\n            nn.Linear(feat_dim, proj_dim, bias=False),\n            nn.BatchNorm1d(proj_dim, affine=False),  # no learnable scale at output\n        )\n        # Predictor: 2-layer MLP with bottleneck\n        self.predictor = nn.Sequential(\n            nn.Linear(proj_dim, pred_hidden, bias=False),\n            nn.BatchNorm1d(pred_hidden), nn.ReLU(inplace=True),\n            nn.Linear(pred_hidden, proj_dim),\n        )\n\n    def forward(self, x1, x2):\n        z1 = self.projector(self.encoder(x1).flatten(1))\n        z2 = self.projector(self.encoder(x2).flatten(1))\n        p1 = self.predictor(z1)\n        p2 = self.predictor(z2)\n        return p1, p2, z1.detach(), z2.detach()  # z is stop-gradiented\n\nmodel = SimSiam()\nprint(\u0027SimSiam parameters:\u0027, sum(p.numel() for p in model.parameters()) // 1_000_000, \u0027M\u0027)\nprint(\u0027Key: z1 and z2 are detached (stop-gradient) before entering loss.\u0027)"},{"type":"heading","level":2,"content":"Stop-Gradient and the Loss Function"},{"type":"text","content":"The SimSiam loss is: D(p, z) = -cos_sim(p, sg(z)) = -(p/‖p‖)·(z/‖z‖) where sg(·) denotes stop-gradient (detach in PyTorch). The symmetrised loss is: L = ½D(p₁, sg(z₂)) + ½D(p₂, sg(z₁)). The stop-gradient is not merely a trick — it is the fundamental mechanism. Without it, the objective reduces to a degenerate problem where the constant solution (all outputs identical) is optimal and easily found by gradient descent. With it, the problem becomes a two-player alternating optimisation."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef simsiam_loss(p1, p2, z1, z2):\n    \"\"\"SimSiam symmetrised loss. z1, z2 must already be stop-gradiented.\n    p1, p2: predictor outputs (grad flows through these)\n    z1, z2: projector outputs (detached — no grad)\n    \"\"\"\n    def D(p, z):\n        \"\"\"Negative cosine similarity: lower is better.\"\"\"\n        p_norm = F.normalize(p, dim=1)\n        z_norm = F.normalize(z, dim=1)  # z is already detached\n        return -(p_norm * z_norm).sum(dim=1).mean()\n    return 0.5 * D(p1, z2) + 0.5 * D(p2, z1)\n\n# Training step\ndef train_step_simsiam(model, x1, x2, optimizer):\n    p1, p2, z1, z2 = model(x1, x2)  # z already detached in forward()\n    loss = simsiam_loss(p1, p2, z1, z2)\n    optimizer.zero_grad()\n    loss.backward()\n    optimizer.step()\n    # Monitor collapse: std of z should stay \u003e 0\n    with torch.no_grad():\n        std = F.normalize(z1, dim=1).std(0).mean().item()\n    return loss.item(), std\n\n# Quick test\ntorch.manual_seed(0)\np1 = torch.randn(32, 2048, requires_grad=True)\np2 = torch.randn(32, 2048, requires_grad=True)\nz1 = torch.randn(32, 2048).detach()\nz2 = torch.randn(32, 2048).detach()\nloss = simsiam_loss(p1, p2, z1, z2)\nprint(f\u0027SimSiam loss on random inputs: {loss.item():.4f}  (expected near 0 for random)\u0027)"},{"type":"heading","level":2,"content":"Collapse Analysis With and Without Stop-Gradient"},{"type":"text","content":"Without stop-gradient, the gradient pushes both z and p to maximise cosine similarity, and the trivial solution — all vectors point to the same direction — achieves loss -1 immediately. With stop-gradient, when computing dL/dp₁, z₂ is treated as a constant. The gradient only flows through p₁, forcing p₁ to match the current z₂ as best as possible without modifying z₂. This creates an alternating optimisation where neither side can unilaterally collapse."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef check_collapse(use_stop_gradient, n_steps=300, seed=7):\n    \"\"\"Run a toy SimSiam and report whether collapse occurs.\"\"\"\n    torch.manual_seed(seed)\n    net = nn.Sequential(nn.Linear(32, 64), nn.ReLU(), nn.Linear(64, 32))\n    pred = nn.Sequential(nn.Linear(32, 16), nn.ReLU(), nn.Linear(16, 32))\n    opt = torch.optim.SGD(list(net.parameters()) + list(pred.parameters()), lr=0.05)\n    stds = []\n    for _ in range(n_steps):\n        x1, x2 = torch.randn(64, 32), torch.randn(64, 32)\n        z1, z2 = F.normalize(net(x1), dim=1), F.normalize(net(x2), dim=1)\n        p1, p2 = pred(z1), pred(z2)\n        if use_stop_gradient:\n            loss = 0.5 * (-(p1 * z2.detach()).sum(1).mean() +\n                          -(p2 * z1.detach()).sum(1).mean())\n        else:\n            loss = 0.5 * (-(p1 * z2).sum(1).mean() +\n                          -(p2 * z1).sum(1).mean())\n        opt.zero_grad(); loss.backward(); opt.step()\n        with torch.no_grad():\n            stds.append(F.normalize(net(torch.randn(64, 32)), dim=1).std(0).mean().item())\n    return stds[-1], min(stds)\n\nfinal_std_sg,   min_std_sg   = check_collapse(True)\nfinal_std_nosg, min_std_nosg = check_collapse(False)\nprint(f\u0027With    stop-grad: final std={final_std_sg:.4f}, min std={min_std_sg:.4f}  → stable\u0027)\nprint(f\u0027Without stop-grad: final std={final_std_nosg:.6f}, min std={min_std_nosg:.6f} → collapsed\u0027)"},{"type":"heading","level":2,"content":"EM Interpretation — Alternating Optimisation"},{"type":"text","content":"SimSiam can be interpreted as an Expectation-Maximisation algorithm. The full loss without stop-gradient is L = E_{T~A}[‖F(x; θ) - F(T(x); θ)‖²] over augmentations. Introducing stop-gradient defines a two-step procedure: (1) E-step: fix θ, compute the optimal predictor (the mean of F(T(x)) over augmentations) — this is what sg(z) represents; (2) M-step: fix the E-step result, update θ to minimise MSE. The predictor approximates the E-step by learning to output the mean representation across augmentations."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef em_interpretation_demo(n_aug=8, n_steps=200, seed=0):\n    \"\"\"Show that the predictor converges to the mean of augmented representations.\n    In EM terms: E-step = predictor learning the mean, M-step = encoder updating.\n    \"\"\"\n    torch.manual_seed(seed)\n    encoder = nn.Linear(16, 8, bias=False)\n    predictor = nn.Linear(8, 8, bias=False)\n    opt_enc  = torch.optim.SGD(encoder.parameters(),   lr=0.05)\n    opt_pred = torch.optim.SGD(predictor.parameters(), lr=0.1)\n    x = torch.randn(1, 16)  # one anchor image\n    for step in range(n_steps):\n        # E-step: update predictor to predict mean of augmented views\n        augmentations = [x + 0.1 * torch.randn_like(x) for _ in range(n_aug)]\n        zs = torch.stack([F.normalize(encoder(aug), dim=1) for aug in augmentations])\n        mean_z = zs.mean(0).detach()  # stop-gradient on target\n        pred_out = predictor(F.normalize(encoder(x), dim=1))\n        loss_e = F.mse_loss(pred_out, mean_z)\n        opt_pred.zero_grad(); loss_e.backward(); opt_pred.step()\n        # M-step: update encoder using predictor\u0027s current target\n        pred_out = predictor(F.normalize(encoder(x), dim=1))\n        target_z = mean_z  # fixed from E-step\n        loss_m = F.mse_loss(pred_out, target_z)\n        opt_enc.zero_grad(); loss_m.backward(); opt_enc.step()\n    return loss_e.item(), loss_m.item()\n\nle, lm = em_interpretation_demo()\nprint(f\u0027E-step final loss: {le:.6f}\u0027)\nprint(f\u0027M-step final loss: {lm:.6f}\u0027)\nprint(\u0027Predictor converges to mean representation across augmentations.\u0027)"},{"type":"callout","variant":"info","title":"Predictor Depth Matters","content":"SimSiam requires the predictor to have at least one hidden layer. A linear predictor (single layer) is insufficient to break the symmetry needed to prevent collapse — a linear map on top of a linear encoder collapses the problem to a trivial rank-1 solution. The hidden layer in the predictor provides the non-linearity needed to implement the E-step approximation faithfully. In practice, a 2-layer MLP with a bottleneck (input 2048 → hidden 512 → output 2048) works well."},{"type":"heading","level":2,"content":"Batch Size and Training Details"},{"type":"text","content":"Unlike SimCLR, SimSiam does not require large batch sizes. Batch sizes of 256–512 are sufficient because there are no in-batch negatives. Training uses SGD with momentum 0.9, weight decay 1e-4, and a cosine learning rate schedule with linear warmup. The learning rate is 0.05 × batch_size/256. No LARS optimiser is needed. Training for 100–800 epochs on ImageNet with ResNet-50 achieves 70.8%–71.3% top-1 linear evaluation accuracy."},{"type":"list","ordered":false,"items":["Batch size 256–512 sufficient — no large batch required (key advantage over SimCLR).","SGD with momentum=0.9, weight decay=1e-4, base_lr=0.05 × batch/256.","Predictor uses higher learning rate than encoder (10× in some ablations).","BN in projector output layer uses affine=False (no learnable scale/bias).","Collapse diagnosis: monitor std(z) — should stay near 0.7 for 128-D unit sphere."]},{"type":"table","headers":["Method","EMA Target","Predictor","Stop-Gradient","Collapse Mechanism","Batch Size","Linear Eval Top-1"],"rows":[["BYOL","Yes (τ=0.996)","Yes","Yes (implicit)","EMA + asymmetry + BN","4096","74.3%"],["SimSiam","No","Yes","Explicit sg(·)","EM alternation","256","71.3%"]]},{"type":"heading","level":2,"content":"When to Choose SimSiam"},{"type":"text","content":"SimSiam is the right choice when compute budget is limited and interpretability matters. Its small batch size (256) and absence of an EMA target network halve the memory footprint compared to BYOL. The EM interpretation provides a clean theoretical story for presentations and papers. The main risk is training instability: if the predictor is under-powered (too shallow or too small) or the learning rate is too high, collapse can occur silently — monitor per-dimension std of z during training and stop early if it drops below 0.1."},{"type":"heading","level":2,"content":"Results and Practical Takeaways"},{"type":"text","content":"SimSiam achieves 71.3% top-1 linear evaluation with ResNet-50 at 200 epochs, improving to 71.3% at 800 epochs. The result is particularly notable because it uses batch size 256 and no EMA — proving that neither large batches nor momentum encoders are necessary for high-quality self-supervised learning. Transfer learning results on Pascal VOC object detection match MoCo v2 within 0.3 AP. The stop-gradient is the single indispensable component: removing it causes collapse within the first few epochs regardless of other hyperparameters."}]"
---
# SimSiam — Collapsing Without Negatives or Momentum

SimSiam (Simple Siamese Networks, Chen & He 2020) strips BYOL down to its minimum: no negatives, no EMA, no large batch size. The only ingredient preventing collapse is the stop-gradient operation on one branch. Despite its simplicity, SimSiam achieves competitive performance (71.3% top-1 on ImageNet with ResNet-50) and provides valuable theoretical insight into why self-supervised learning without negatives can work through an expectation-maximisation lens.

## Architecture — Encoder, Projector, Predictor

SimSiam uses a symmetric Siamese architecture with one asymmetric element. Both branches share the same encoder f (ResNet) and projector h (3-layer MLP with BN). On top of one branch, a two-layer MLP predictor p is applied. The key insight: the predictor is applied only to one side; the other side is stop-gradiented. There is no separate target network, no queue, no EMA — both branches share weights.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import torchvision.models as models

class SimSiam(nn.Module):
    """SimSiam: shared encoder + projector, asymmetric predictor + stop-gradient."""
    def __init__(self, backbone_fn=models.resnet50, proj_dim=2048, pred_hidden=512):
        super().__init__()
        base = backbone_fn(weights=None)
        feat_dim = base.fc.in_features  # 2048
        # Encoder (backbone without final fc)
        self.encoder = nn.Sequential(*list(base.children())[:-1])
        # Projector: 3-layer MLP with BN (dim stays 2048)
        self.projector = nn.Sequential(
            nn.Linear(feat_dim, feat_dim, bias=False),
            nn.BatchNorm1d(feat_dim), nn.ReLU(inplace=True),
            nn.Linear(feat_dim, feat_dim, bias=False),
            nn.BatchNorm1d(feat_dim), nn.ReLU(inplace=True),
            nn.Linear(feat_dim, proj_dim, bias=False),
            nn.BatchNorm1d(proj_dim, affine=False),  # no learnable scale at output
        )
        # Predictor: 2-layer MLP with bottleneck
        self.predictor = nn.Sequential(
            nn.Linear(proj_dim, pred_hidden, bias=False),
            nn.BatchNorm1d(pred_hidden), nn.ReLU(inplace=True),
            nn.Linear(pred_hidden, proj_dim),
        )

    def forward(self, x1, x2):
        z1 = self.projector(self.encoder(x1).flatten(1))
        z2 = self.projector(self.encoder(x2).flatten(1))
        p1 = self.predictor(z1)
        p2 = self.predictor(z2)
        return p1, p2, z1.detach(), z2.detach()  # z is stop-gradiented

model = SimSiam()
print('SimSiam parameters:', sum(p.numel() for p in model.parameters()) // 1_000_000, 'M')
print('Key: z1 and z2 are detached (stop-gradient) before entering loss.')
```

## Stop-Gradient and the Loss Function

The SimSiam loss is: D(p, z) = -cos_sim(p, sg(z)) = -(p/‖p‖)·(z/‖z‖) where sg(·) denotes stop-gradient (detach in PyTorch). The symmetrised loss is: L = ½D(p₁, sg(z₂)) + ½D(p₂, sg(z₁)). The stop-gradient is not merely a trick — it is the fundamental mechanism. Without it, the objective reduces to a degenerate problem where the constant solution (all outputs identical) is optimal and easily found by gradient descent. With it, the problem becomes a two-player alternating optimisation.

```python
import torch
import torch.nn.functional as F

def simsiam_loss(p1, p2, z1, z2):
    """SimSiam symmetrised loss. z1, z2 must already be stop-gradiented.
    p1, p2: predictor outputs (grad flows through these)
    z1, z2: projector outputs (detached — no grad)
    """
    def D(p, z):
        """Negative cosine similarity: lower is better."""
        p_norm = F.normalize(p, dim=1)
        z_norm = F.normalize(z, dim=1)  # z is already detached
        return -(p_norm * z_norm).sum(dim=1).mean()
    return 0.5 * D(p1, z2) + 0.5 * D(p2, z1)

# Training step
def train_step_simsiam(model, x1, x2, optimizer):
    p1, p2, z1, z2 = model(x1, x2)  # z already detached in forward()
    loss = simsiam_loss(p1, p2, z1, z2)
    optimizer.zero_grad()
    loss.backward()
    optimizer.step()
    # Monitor collapse: std of z should stay > 0
    with torch.no_grad():
        std = F.normalize(z1, dim=1).std(0).mean().item()
    return loss.item(), std

# Quick test
torch.manual_seed(0)
p1 = torch.randn(32, 2048, requires_grad=True)
p2 = torch.randn(32, 2048, requires_grad=True)
z1 = torch.randn(32, 2048).detach()
z2 = torch.randn(32, 2048).detach()
loss = simsiam_loss(p1, p2, z1, z2)
print(f'SimSiam loss on random inputs: {loss.item():.4f}  (expected near 0 for random)')
```

## Collapse Analysis With and Without Stop-Gradient

Without stop-gradient, the gradient pushes both z and p to maximise cosine similarity, and the trivial solution — all vectors point to the same direction — achieves loss -1 immediately. With stop-gradient, when computing dL/dp₁, z₂ is treated as a constant. The gradient only flows through p₁, forcing p₁ to match the current z₂ as best as possible without modifying z₂. This creates an alternating optimisation where neither side can unilaterally collapse.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def check_collapse(use_stop_gradient, n_steps=300, seed=7):
    """Run a toy SimSiam and report whether collapse occurs."""
    torch.manual_seed(seed)
    net = nn.Sequential(nn.Linear(32, 64), nn.ReLU(), nn.Linear(64, 32))
    pred = nn.Sequential(nn.Linear(32, 16), nn.ReLU(), nn.Linear(16, 32))
    opt = torch.optim.SGD(list(net.parameters()) + list(pred.parameters()), lr=0.05)
    stds = []
    for _ in range(n_steps):
        x1, x2 = torch.randn(64, 32), torch.randn(64, 32)
        z1, z2 = F.normalize(net(x1), dim=1), F.normalize(net(x2), dim=1)
        p1, p2 = pred(z1), pred(z2)
        if use_stop_gradient:
            loss = 0.5 * (-(p1 * z2.detach()).sum(1).mean() +
                          -(p2 * z1.detach()).sum(1).mean())
        else:
            loss = 0.5 * (-(p1 * z2).sum(1).mean() +
                          -(p2 * z1).sum(1).mean())
        opt.zero_grad(); loss.backward(); opt.step()
        with torch.no_grad():
            stds.append(F.normalize(net(torch.randn(64, 32)), dim=1).std(0).mean().item())
    return stds[-1], min(stds)

final_std_sg,   min_std_sg   = check_collapse(True)
final_std_nosg, min_std_nosg = check_collapse(False)
print(f'With    stop-grad: final std={final_std_sg:.4f}, min std={min_std_sg:.4f}  → stable')
print(f'Without stop-grad: final std={final_std_nosg:.6f}, min std={min_std_nosg:.6f} → collapsed')
```

## EM Interpretation — Alternating Optimisation

SimSiam can be interpreted as an Expectation-Maximisation algorithm. The full loss without stop-gradient is L = E_{T~A}[‖F(x; θ) - F(T(x); θ)‖²] over augmentations. Introducing stop-gradient defines a two-step procedure: (1) E-step: fix θ, compute the optimal predictor (the mean of F(T(x)) over augmentations) — this is what sg(z) represents; (2) M-step: fix the E-step result, update θ to minimise MSE. The predictor approximates the E-step by learning to output the mean representation across augmentations.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def em_interpretation_demo(n_aug=8, n_steps=200, seed=0):
    """Show that the predictor converges to the mean of augmented representations.
    In EM terms: E-step = predictor learning the mean, M-step = encoder updating.
    """
    torch.manual_seed(seed)
    encoder = nn.Linear(16, 8, bias=False)
    predictor = nn.Linear(8, 8, bias=False)
    opt_enc  = torch.optim.SGD(encoder.parameters(),   lr=0.05)
    opt_pred = torch.optim.SGD(predictor.parameters(), lr=0.1)
    x = torch.randn(1, 16)  # one anchor image
    for step in range(n_steps):
        # E-step: update predictor to predict mean of augmented views
        augmentations = [x + 0.1 * torch.randn_like(x) for _ in range(n_aug)]
        zs = torch.stack([F.normalize(encoder(aug), dim=1) for aug in augmentations])
        mean_z = zs.mean(0).detach()  # stop-gradient on target
        pred_out = predictor(F.normalize(encoder(x), dim=1))
        loss_e = F.mse_loss(pred_out, mean_z)
        opt_pred.zero_grad(); loss_e.backward(); opt_pred.step()
        # M-step: update encoder using predictor's current target
        pred_out = predictor(F.normalize(encoder(x), dim=1))
        target_z = mean_z  # fixed from E-step
        loss_m = F.mse_loss(pred_out, target_z)
        opt_enc.zero_grad(); loss_m.backward(); opt_enc.step()
    return loss_e.item(), loss_m.item()

le, lm = em_interpretation_demo()
print(f'E-step final loss: {le:.6f}')
print(f'M-step final loss: {lm:.6f}')
print('Predictor converges to mean representation across augmentations.')
```

> **Predictor Depth Matters**: SimSiam requires the predictor to have at least one hidden layer. A linear predictor (single layer) is insufficient to break the symmetry needed to prevent collapse — a linear map on top of a linear encoder collapses the problem to a trivial rank-1 solution. The hidden layer in the predictor provides the non-linearity needed to implement the E-step approximation faithfully. In practice, a 2-layer MLP with a bottleneck (input 2048 → hidden 512 → output 2048) works well.

## Batch Size and Training Details

Unlike SimCLR, SimSiam does not require large batch sizes. Batch sizes of 256–512 are sufficient because there are no in-batch negatives. Training uses SGD with momentum 0.9, weight decay 1e-4, and a cosine learning rate schedule with linear warmup. The learning rate is 0.05 × batch_size/256. No LARS optimiser is needed. Training for 100–800 epochs on ImageNet with ResNet-50 achieves 70.8%–71.3% top-1 linear evaluation accuracy.

- Batch size 256–512 sufficient — no large batch required (key advantage over SimCLR).
- SGD with momentum=0.9, weight decay=1e-4, base_lr=0.05 × batch/256.
- Predictor uses higher learning rate than encoder (10× in some ablations).
- BN in projector output layer uses affine=False (no learnable scale/bias).
- Collapse diagnosis: monitor std(z) — should stay near 0.7 for 128-D unit sphere.

| Method | EMA Target | Predictor | Stop-Gradient | Collapse Mechanism | Batch Size | Linear Eval Top-1 |
| --- | --- | --- | --- | --- | --- | --- |
| BYOL | Yes (τ=0.996) | Yes | Yes (implicit) | EMA + asymmetry + BN | 4096 | 74.3% |
| SimSiam | No | Yes | Explicit sg(·) | EM alternation | 256 | 71.3% |

## When to Choose SimSiam

SimSiam is the right choice when compute budget is limited and interpretability matters. Its small batch size (256) and absence of an EMA target network halve the memory footprint compared to BYOL. The EM interpretation provides a clean theoretical story for presentations and papers. The main risk is training instability: if the predictor is under-powered (too shallow or too small) or the learning rate is too high, collapse can occur silently — monitor per-dimension std of z during training and stop early if it drops below 0.1.

## Results and Practical Takeaways

SimSiam achieves 71.3% top-1 linear evaluation with ResNet-50 at 200 epochs, improving to 71.3% at 800 epochs. The result is particularly notable because it uses batch size 256 and no EMA — proving that neither large batches nor momentum encoders are necessary for high-quality self-supervised learning. Transfer learning results on Pascal VOC object detection match MoCo v2 within 0.3 AP. The stop-gradient is the single indispensable component: removing it causes collapse within the first few epochs regardless of other hyperparameters.

