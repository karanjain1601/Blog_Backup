---
title: "Conditional GAN (cGAN) — Class-Conditional and Projection Discriminator"
slug: "conditional-gan"
description: "Condition both generator G(z,y) and discriminator D(x,y) on class label y; derive the projection discriminator D(x,y)=phi(x)^T V_y + psi(phi(x)); implement class-conditional BatchNorm as used in BigGAN; and apply the truncation trick to trade sample quality for diversity."
tags: ["deep-learning", "generative-models", "gans", "normalizing-flows"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"A conditional GAN (cGAN) extends the vanilla GAN by supplying both the generator G and discriminator D with a conditioning signal y — typically a class label. The generator learns G: (z,y) → x, producing images belonging to class y. The discriminator learns to distinguish real (x,y) pairs from fake ones. Conditioning enables class-specific generation, reduces within-class sample diversity, and allows controllable synthesis — the foundation for large-scale models such as BigGAN and modern text-conditional diffusion models."},{"type":"heading","level":2,"content":"Conditioning Generator and Discriminator"},{"type":"text","content":"The simplest strategy embeds y into a dense vector via a learned nn.Embedding, then concatenates it to the noise vector z before feeding G. For D, the label embedding is concatenated to the flattened image. Embedding dimension (50–256) is a hyperparameter. The objective remains the standard GAN loss — BCE or hinge — with the pair (x,y) as input rather than x alone. This approach is called label concatenation conditioning and serves as the baseline against which projection discriminators are compared."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass ConditionalGenerator(nn.Module):\n    def __init__(self, z_dim=100, n_classes=10, img_dim=784, embed_dim=50):\n        super().__init__()\n        self.label_embed = nn.Embedding(n_classes, embed_dim)\n        self.net = nn.Sequential(\n            nn.Linear(z_dim + embed_dim, 256), nn.LeakyReLU(0.2),\n            nn.Linear(256, 512), nn.LeakyReLU(0.2),\n            nn.Linear(512, img_dim), nn.Tanh())\n    def forward(self, z, labels):\n        return self.net(torch.cat([z, self.label_embed(labels)], 1))\n\nclass ConditionalDiscriminator(nn.Module):\n    def __init__(self, n_classes=10, img_dim=784, embed_dim=50):\n        super().__init__()\n        self.label_embed = nn.Embedding(n_classes, embed_dim)\n        self.net = nn.Sequential(\n            nn.Linear(img_dim + embed_dim, 512), nn.LeakyReLU(0.2),\n            nn.Linear(512, 256), nn.LeakyReLU(0.2),\n            nn.Linear(256, 1))\n    def forward(self, x, labels):\n        return self.net(torch.cat([x, self.label_embed(labels)], 1))\n\ntorch.manual_seed(0)\nG, D = ConditionalGenerator(), ConditionalDiscriminator()\nz = torch.randn(8, 100)\nlabels = torch.randint(0, 10, (8,))\nfake = G(z, labels)\nscore = D(fake.detach(), labels)\nprint(\u0027Fake shape:\u0027, fake.shape, \u0027| Score shape:\u0027, score.shape)"},{"type":"heading","level":2,"content":"Projection Discriminator (Miyato 2018)"},{"type":"text","content":"Concatenating the label embedding to D\u0027s input treats x and y symmetrically, ignoring their different statistical roles. The projection discriminator (Miyato \u0026 Koyama 2018) computes D(x,y) = φ(x)ᵀV_y + ψ(φ(x)), where φ is a deep feature extractor, V is the label embedding matrix, and ψ is an unconditional linear head. The inner product φ(x)ᵀV_y directly scores how well image features align with the class embedding — a principled factorisation grounded in the theory of energy-based models that empirically achieves lower FID than concatenation conditioning."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass ProjectionDiscriminator(nn.Module):\n    \u0027\u0027\u0027Miyato \u0026 Koyama 2018: D(x,y) = phi(x)^T V_y + psi(phi(x)).\u0027\u0027\u0027\n    def __init__(self, feature_dim=256, n_classes=10):\n        super().__init__()\n        self.phi = nn.Sequential(\n            nn.Linear(784, 512), nn.LeakyReLU(0.2),\n            nn.Linear(512, feature_dim), nn.LeakyReLU(0.2))\n        self.V   = nn.Embedding(n_classes, feature_dim)  # label matrix\n        self.psi = nn.Linear(feature_dim, 1)             # unconditional head\n\n    def forward(self, x, labels):\n        h   = self.phi(x)                         # (B, feature_dim)\n        v_y = self.V(labels)                      # (B, feature_dim)\n        proj   = (h * v_y).sum(1, keepdim=True)  # inner product (B, 1)\n        uncond = self.psi(h)                      # bias term    (B, 1)\n        return proj + uncond\n\ntorch.manual_seed(1)\nD_proj = ProjectionDiscriminator()\nx = torch.randn(8, 784)\nlabels = torch.randint(0, 10, (8,))\nout = D_proj(x, labels)\nprint(\u0027Projection D output shape:\u0027, out.shape)  # (8, 1)"},{"type":"heading","level":2,"content":"Class-Conditional Batch Normalization"},{"type":"text","content":"Class-conditional BatchNorm (cBN) uses a separate (γ_y, β_y) pair for each class y instead of global γ and β. Features are normalised across the batch as usual, but the affine transform is class-specific: h = γ_y · BN(h) + β_y. BigGAN applies cBN throughout the generator, allowing the network to modulate activations at every layer based on class identity. In BigGAN, γ_y and β_y are linear projections of a shared class embedding rather than direct lookups, making the conditioning parametrically efficient."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass ConditionalBatchNorm(nn.Module):\n    \u0027\u0027\u0027Separate gamma/beta per class, as used in BigGAN generator.\u0027\u0027\u0027\n    def __init__(self, num_features, n_classes=10):\n        super().__init__()\n        self.bn    = nn.BatchNorm1d(num_features, affine=False)\n        self.gamma = nn.Embedding(n_classes, num_features)\n        self.beta  = nn.Embedding(n_classes, num_features)\n        nn.init.ones_(self.gamma.weight)\n        nn.init.zeros_(self.beta.weight)\n\n    def forward(self, x, labels):\n        out = self.bn(x)\n        g   = self.gamma(labels)  # (B, num_features)\n        b   = self.beta(labels)   # (B, num_features)\n        return g * out + b\n\ncbn = ConditionalBatchNorm(64, 10)\nx   = torch.randn(16, 64)\ny0  = cbn(x, torch.zeros(16, dtype=torch.long))  # class 0\ny1  = cbn(x, torch.ones(16,  dtype=torch.long))  # class 1\ndiff = (y0 - y1).abs().mean().item()\nprint(\u0027Class-0 vs class-1 output diff:\u0027, round(diff, 4), \u0027(expect \u003e 0)\u0027)"},{"type":"heading","level":2,"content":"BigGAN: Large-Scale Conditional Generation"},{"type":"text","content":"BigGAN (Brock et al. 2018) scales conditional GANs to ImageNet 512×512 using batch size 2048, channel multiplier ×4, self-attention at 64×64 resolution, spectral normalisation on D, and orthogonal regularisation on weights. Class-conditional BatchNorm is applied at every residual block in G, with γ_y and β_y computed from a shared class embedding concatenated to z. BigGAN achieves FID ~7 on ImageNet 128×128 versus ~28 for the prior best — demonstrating that scale and well-designed conditioning together close much of the realism gap."},{"type":"callout","variant":"info","title":"BigGAN Truncation and Class Leakage","content":"BigGAN uses truncated Normal sampling at test time (truncation trick) and observes a trade-off: smaller truncation threshold gives sharper but less diverse images. A known failure mode is class leakage — generating features from nearby classes — which worsens at high truncation. BigGAN mitigates this by training with orthogonal regularisation that keeps weights on the unit sphere, reducing mode collapse and leakage."},{"type":"heading","level":2,"content":"Truncation Trick: Quality vs Diversity"},{"type":"text","content":"The truncation trick samples z from a truncated Normal: reject samples with ‖z‖/√d \u003e τ and resample. Small τ constrains z to a high-density region of N(0,I), so G maps it to high-quality typical images. Large τ allows rare z values, increasing diversity but risking artefacts. The FID–IS trade-off as τ varies traces a Pareto frontier. Truncation is a test-time technique; G is trained without it, then truncation is applied only during evaluation or generation."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef truncated_sample(G, n_classes=10, n_samples=8,\n                     z_dim=100, thresholds=(0.3, 0.7, 1.0, 1.5)):\n    \u0027\u0027\u0027Sample z from truncated Normal; report diversity per threshold.\u0027\u0027\u0027\n    G.eval()\n    for tau in thresholds:\n        pool  = torch.randn(n_samples * 200, z_dim)\n        norms = pool.norm(dim=1) / np.sqrt(z_dim)\n        ok = pool[norms \u003c tau]\n        ok = ok[:n_samples] if len(ok) \u003e= n_samples else pool[:n_samples]\n        lbl = torch.randint(0, n_classes, (len(ok),))\n        with torch.no_grad():\n            fake = G(ok, lbl)\n        print(\u0027tau={:.1f}  accepted={}  fake_std={:.4f}\u0027.format(\n              tau, len(ok), fake.std().item()))\n\nG_demo = ConditionalGenerator()\ntruncated_sample(G_demo)\nprint(\u0027Lower tau: fewer outlier z -\u003e higher quality, lower diversity\u0027)"},{"type":"heading","level":2,"content":"Text and Cross-Attention Conditioning"},{"type":"text","content":"Modern text-conditional generation replaces the class embedding with a rich text encoder. CLIP encodes a text prompt into a 512-d vector that serves as the conditioning signal — passed to G via projection or cross-attention. In cross-attention conditioning (LDM/Stable Diffusion), queries come from spatial image features and keys/values from the text embedding, allowing the model to attend to specific words for specific regions. CLIP conditioning also enables zero-shot generation: describe any concept in text and generate samples without class-specific training data."},{"type":"list","ordered":false,"items":["Label concatenation: embed y, concatenate to z and D input — simplest approach for small n_classes.","Projection D: D(x,y)=phi(x)^T V_y + psi(phi(x)) — principled inner-product factorisation, better FID.","Class-conditional BN: per-class gamma/beta at every layer — BigGAN approach for large-scale generation.","Truncation trick: sample z from truncated Normal at test time — trades diversity for quality.","CLIP conditioning: text embedding as y — enables open-vocabulary zero-shot generation.","Cross-attention: attend over text tokens at each spatial scale — Stable Diffusion / LDM architecture."]},{"type":"heading","level":2,"content":"Unconditional vs Conditional GAN Comparison"},{"type":"table","headers":["Aspect","Unconditional GAN","cGAN (concat)","Projection D","BigGAN"],"rows":[["Label input","None","concat to z and D input","inner product in D only","cBN + shared class embed"],["Controls class","No","Yes","Yes","Yes"],["BN conditioning","Standard BN","Standard BN","Standard BN","Class-conditional BN"],["FID CIFAR-10 (approx)","20–30","12–18","9–14","7–9"],["Strengths","Simple baseline","Easy to implement","Principled, better FID","SOTA quality at scale"]]},{"type":"text","content":"The projection discriminator and class-conditional BatchNorm are complementary: the former improves how D uses the label, while the latter improves how G uses it. Combined in BigGAN, they achieve substantially better class-conditional FID than naive concatenation, setting the standard for large-scale conditional image synthesis before the diffusion era."},{"type":"divider"}]"
---
# Conditional GAN (cGAN) — Class-Conditional and Projection Discriminator

A conditional GAN (cGAN) extends the vanilla GAN by supplying both the generator G and discriminator D with a conditioning signal y — typically a class label. The generator learns G: (z,y) → x, producing images belonging to class y. The discriminator learns to distinguish real (x,y) pairs from fake ones. Conditioning enables class-specific generation, reduces within-class sample diversity, and allows controllable synthesis — the foundation for large-scale models such as BigGAN and modern text-conditional diffusion models.

## Conditioning Generator and Discriminator

The simplest strategy embeds y into a dense vector via a learned nn.Embedding, then concatenates it to the noise vector z before feeding G. For D, the label embedding is concatenated to the flattened image. Embedding dimension (50–256) is a hyperparameter. The objective remains the standard GAN loss — BCE or hinge — with the pair (x,y) as input rather than x alone. This approach is called label concatenation conditioning and serves as the baseline against which projection discriminators are compared.

```python
import torch
import torch.nn as nn

class ConditionalGenerator(nn.Module):
    def __init__(self, z_dim=100, n_classes=10, img_dim=784, embed_dim=50):
        super().__init__()
        self.label_embed = nn.Embedding(n_classes, embed_dim)
        self.net = nn.Sequential(
            nn.Linear(z_dim + embed_dim, 256), nn.LeakyReLU(0.2),
            nn.Linear(256, 512), nn.LeakyReLU(0.2),
            nn.Linear(512, img_dim), nn.Tanh())
    def forward(self, z, labels):
        return self.net(torch.cat([z, self.label_embed(labels)], 1))

class ConditionalDiscriminator(nn.Module):
    def __init__(self, n_classes=10, img_dim=784, embed_dim=50):
        super().__init__()
        self.label_embed = nn.Embedding(n_classes, embed_dim)
        self.net = nn.Sequential(
            nn.Linear(img_dim + embed_dim, 512), nn.LeakyReLU(0.2),
            nn.Linear(512, 256), nn.LeakyReLU(0.2),
            nn.Linear(256, 1))
    def forward(self, x, labels):
        return self.net(torch.cat([x, self.label_embed(labels)], 1))

torch.manual_seed(0)
G, D = ConditionalGenerator(), ConditionalDiscriminator()
z = torch.randn(8, 100)
labels = torch.randint(0, 10, (8,))
fake = G(z, labels)
score = D(fake.detach(), labels)
print('Fake shape:', fake.shape, '| Score shape:', score.shape)
```

## Projection Discriminator (Miyato 2018)

Concatenating the label embedding to D's input treats x and y symmetrically, ignoring their different statistical roles. The projection discriminator (Miyato & Koyama 2018) computes D(x,y) = φ(x)ᵀV_y + ψ(φ(x)), where φ is a deep feature extractor, V is the label embedding matrix, and ψ is an unconditional linear head. The inner product φ(x)ᵀV_y directly scores how well image features align with the class embedding — a principled factorisation grounded in the theory of energy-based models that empirically achieves lower FID than concatenation conditioning.

```python
import torch
import torch.nn as nn

class ProjectionDiscriminator(nn.Module):
    '''Miyato & Koyama 2018: D(x,y) = phi(x)^T V_y + psi(phi(x)).'''
    def __init__(self, feature_dim=256, n_classes=10):
        super().__init__()
        self.phi = nn.Sequential(
            nn.Linear(784, 512), nn.LeakyReLU(0.2),
            nn.Linear(512, feature_dim), nn.LeakyReLU(0.2))
        self.V   = nn.Embedding(n_classes, feature_dim)  # label matrix
        self.psi = nn.Linear(feature_dim, 1)             # unconditional head

    def forward(self, x, labels):
        h   = self.phi(x)                         # (B, feature_dim)
        v_y = self.V(labels)                      # (B, feature_dim)
        proj   = (h * v_y).sum(1, keepdim=True)  # inner product (B, 1)
        uncond = self.psi(h)                      # bias term    (B, 1)
        return proj + uncond

torch.manual_seed(1)
D_proj = ProjectionDiscriminator()
x = torch.randn(8, 784)
labels = torch.randint(0, 10, (8,))
out = D_proj(x, labels)
print('Projection D output shape:', out.shape)  # (8, 1)
```

## Class-Conditional Batch Normalization

Class-conditional BatchNorm (cBN) uses a separate (γ_y, β_y) pair for each class y instead of global γ and β. Features are normalised across the batch as usual, but the affine transform is class-specific: h = γ_y · BN(h) + β_y. BigGAN applies cBN throughout the generator, allowing the network to modulate activations at every layer based on class identity. In BigGAN, γ_y and β_y are linear projections of a shared class embedding rather than direct lookups, making the conditioning parametrically efficient.

```python
import torch
import torch.nn as nn

class ConditionalBatchNorm(nn.Module):
    '''Separate gamma/beta per class, as used in BigGAN generator.'''
    def __init__(self, num_features, n_classes=10):
        super().__init__()
        self.bn    = nn.BatchNorm1d(num_features, affine=False)
        self.gamma = nn.Embedding(n_classes, num_features)
        self.beta  = nn.Embedding(n_classes, num_features)
        nn.init.ones_(self.gamma.weight)
        nn.init.zeros_(self.beta.weight)

    def forward(self, x, labels):
        out = self.bn(x)
        g   = self.gamma(labels)  # (B, num_features)
        b   = self.beta(labels)   # (B, num_features)
        return g * out + b

cbn = ConditionalBatchNorm(64, 10)
x   = torch.randn(16, 64)
y0  = cbn(x, torch.zeros(16, dtype=torch.long))  # class 0
y1  = cbn(x, torch.ones(16,  dtype=torch.long))  # class 1
diff = (y0 - y1).abs().mean().item()
print('Class-0 vs class-1 output diff:', round(diff, 4), '(expect > 0)')
```

## BigGAN: Large-Scale Conditional Generation

BigGAN (Brock et al. 2018) scales conditional GANs to ImageNet 512×512 using batch size 2048, channel multiplier ×4, self-attention at 64×64 resolution, spectral normalisation on D, and orthogonal regularisation on weights. Class-conditional BatchNorm is applied at every residual block in G, with γ_y and β_y computed from a shared class embedding concatenated to z. BigGAN achieves FID ~7 on ImageNet 128×128 versus ~28 for the prior best — demonstrating that scale and well-designed conditioning together close much of the realism gap.

> **BigGAN Truncation and Class Leakage**: BigGAN uses truncated Normal sampling at test time (truncation trick) and observes a trade-off: smaller truncation threshold gives sharper but less diverse images. A known failure mode is class leakage — generating features from nearby classes — which worsens at high truncation. BigGAN mitigates this by training with orthogonal regularisation that keeps weights on the unit sphere, reducing mode collapse and leakage.

## Truncation Trick: Quality vs Diversity

The truncation trick samples z from a truncated Normal: reject samples with ‖z‖/√d > τ and resample. Small τ constrains z to a high-density region of N(0,I), so G maps it to high-quality typical images. Large τ allows rare z values, increasing diversity but risking artefacts. The FID–IS trade-off as τ varies traces a Pareto frontier. Truncation is a test-time technique; G is trained without it, then truncation is applied only during evaluation or generation.

```python
import torch
import numpy as np

def truncated_sample(G, n_classes=10, n_samples=8,
                     z_dim=100, thresholds=(0.3, 0.7, 1.0, 1.5)):
    '''Sample z from truncated Normal; report diversity per threshold.'''
    G.eval()
    for tau in thresholds:
        pool  = torch.randn(n_samples * 200, z_dim)
        norms = pool.norm(dim=1) / np.sqrt(z_dim)
        ok = pool[norms < tau]
        ok = ok[:n_samples] if len(ok) >= n_samples else pool[:n_samples]
        lbl = torch.randint(0, n_classes, (len(ok),))
        with torch.no_grad():
            fake = G(ok, lbl)
        print('tau={:.1f}  accepted={}  fake_std={:.4f}'.format(
              tau, len(ok), fake.std().item()))

G_demo = ConditionalGenerator()
truncated_sample(G_demo)
print('Lower tau: fewer outlier z -> higher quality, lower diversity')
```

## Text and Cross-Attention Conditioning

Modern text-conditional generation replaces the class embedding with a rich text encoder. CLIP encodes a text prompt into a 512-d vector that serves as the conditioning signal — passed to G via projection or cross-attention. In cross-attention conditioning (LDM/Stable Diffusion), queries come from spatial image features and keys/values from the text embedding, allowing the model to attend to specific words for specific regions. CLIP conditioning also enables zero-shot generation: describe any concept in text and generate samples without class-specific training data.

- Label concatenation: embed y, concatenate to z and D input — simplest approach for small n_classes.
- Projection D: D(x,y)=phi(x)^T V_y + psi(phi(x)) — principled inner-product factorisation, better FID.
- Class-conditional BN: per-class gamma/beta at every layer — BigGAN approach for large-scale generation.
- Truncation trick: sample z from truncated Normal at test time — trades diversity for quality.
- CLIP conditioning: text embedding as y — enables open-vocabulary zero-shot generation.
- Cross-attention: attend over text tokens at each spatial scale — Stable Diffusion / LDM architecture.

## Unconditional vs Conditional GAN Comparison

| Aspect | Unconditional GAN | cGAN (concat) | Projection D | BigGAN |
| --- | --- | --- | --- | --- |
| Label input | None | concat to z and D input | inner product in D only | cBN + shared class embed |
| Controls class | No | Yes | Yes | Yes |
| BN conditioning | Standard BN | Standard BN | Standard BN | Class-conditional BN |
| FID CIFAR-10 (approx) | 20–30 | 12–18 | 9–14 | 7–9 |
| Strengths | Simple baseline | Easy to implement | Principled, better FID | SOTA quality at scale |

The projection discriminator and class-conditional BatchNorm are complementary: the former improves how D uses the label, while the latter improves how G uses it. Combined in BigGAN, they achieve substantially better class-conditional FID than naive concatenation, setting the standard for large-scale conditional image synthesis before the diffusion era.

---

