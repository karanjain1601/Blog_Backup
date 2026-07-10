---
title: "GAN Evaluation — FID, IS, and Precision/Recall"
slug: "gan-evaluation-fid"
description: "Evaluating generative models is non-trivial because there is no single ground truth. Covers Inception Score (IS), Fréchet Inception Distance (FID), CLIP-FID, and the precision/recall decomposition that separates sample quality from diversity."
tags: ["deep-learning", "generative-models", "gans", "normalizing-flows"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Evaluating generative models is fundamentally harder than discriminative models: there is no held-out test set with labels, and visual quality is subjective. The field has converged on automatic metrics computed over large sample sets — primarily FID and IS — but each has failure modes. Understanding what each metric measures, what biases it has, and when it misleads is essential for correctly interpreting GAN training progress and comparing models across papers."},{"type":"heading","level":2,"content":"Inception Score (IS)"},{"type":"text","content":"IS (Salimans et al. 2016) measures two properties using a pretrained Inception v3 classifier: (1) quality — individual images should have confident (low-entropy) class predictions p(y|x); (2) diversity — the marginal p(y) = E_x[p(y|x)] should be uniform over classes. IS = exp(E_x[KL(p(y|x) ‖ p(y))]). Higher IS is better. Problems: IS does not compare generated images to real images at all — a model memorising the training set with perfect class balance achieves maximum IS. It is also sensitive to the Inception preprocessing and known to be gameable."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef inception_score(pyx_all, n_splits=10):\n    \u0027\u0027\u0027IS from pre-extracted p(y|x) softmax probabilities.\n    pyx_all: (N, C) numpy array of class probabilities.\n    Returns (mean IS, std IS) across splits.\u0027\u0027\u0027\n    N, C = pyx_all.shape\n    split_sz = N // n_splits\n    scores = []\n    for i in range(n_splits):\n        part = pyx_all[i*split_sz : (i+1)*split_sz]  # (M, C)\n        py   = part.mean(axis=0, keepdims=True)        # marginal p(y)\n        kl   = np.sum(part * (np.log(part + 1e-10) -\n                              np.log(py   + 1e-10)), axis=1)  # per-sample KL\n        scores.append(float(np.exp(kl.mean())))\n    return float(np.mean(scores)), float(np.std(scores))\n\nnp.random.seed(42)\nN, C = 1000, 10\n# High-quality: peaked, diverse -\u003e high IS\npyx_good = np.eye(C)[np.random.randint(0, C, N)] * 0.9 + 0.01\npyx_good /= pyx_good.sum(1, keepdims=True)\nmean_is, std_is = inception_score(pyx_good)\nprint(\u0027High-quality IS: {:.2f} +/- {:.2f}\u0027.format(mean_is, std_is))\n# Low-diversity: all predict class 0\npyx_bad = np.zeros((N, C)); pyx_bad[:, 0] = 0.99; pyx_bad[:, 1:] = 0.01/9\nmean_b, std_b = inception_score(pyx_bad)\nprint(\u0027Low-diversity IS: {:.2f} +/- {:.2f}\u0027.format(mean_b, std_b))"},{"type":"heading","level":2,"content":"Fréchet Inception Distance (FID)"},{"type":"text","content":"FID (Heusel et al. 2017) compares the distribution of real images to that of generated images using features extracted from Inception v3\u0027s pool3 layer (2048-d). Both sets of features are modelled as multivariate Gaussians; FID is the Fréchet distance between them: FID = ‖μ_r − μ_g‖² + Tr(Σ_r + Σ_g − 2(Σ_rΣ_g)^{1/2}). Lower FID means the generated distribution is closer to real. FID is sensitive to both quality (Σ mismatch from blurry images) and diversity (μ mismatch from mode collapse). Standard practice: use ≥10K generated and ≥10K real samples to stabilise the estimate."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.linalg import sqrtm\n\ndef frechet_distance(mu1, sigma1, mu2, sigma2, eps=1e-6):\n    \u0027\u0027\u0027FID = ||mu1-mu2||^2 + Tr(sigma1 + sigma2 - 2*sqrtm(sigma1@sigma2)).\u0027\u0027\u0027\n    diff = mu1 - mu2\n    covmean, _ = sqrtm(sigma1 @ sigma2, disp=False)\n    if not np.isfinite(covmean).all():\n        offset = np.eye(sigma1.shape[0]) * eps\n        covmean = sqrtm((sigma1 + offset) @ (sigma2 + offset))\n    if np.iscomplexobj(covmean):\n        covmean = covmean.real\n    return float(diff @ diff + np.trace(sigma1 + sigma2 - 2*covmean))\n\nnp.random.seed(0)\nd = 256   # reduced from 2048 for demo speed\nN = 500\nreal_feats = np.random.randn(N, d)\n# Same distribution -\u003e FID near 0\nfake_same = np.random.randn(N, d)\nmu_r, sig_r = real_feats.mean(0), np.cov(real_feats, rowvar=False)\nmu_s, sig_s = fake_same.mean(0),  np.cov(fake_same,  rowvar=False)\nfid_good = frechet_distance(mu_r, sig_r, mu_s, sig_s)\nprint(\u0027FID (same dist): {:.2f}\u0027.format(fid_good))\n# Shifted distribution -\u003e higher FID\nfake_shift = np.random.randn(N, d) + 0.5\nmu_sh, sig_sh = fake_shift.mean(0), np.cov(fake_shift, rowvar=False)\nfid_bad = frechet_distance(mu_r, sig_r, mu_sh, sig_sh)\nprint(\u0027FID (shifted):   {:.2f}\u0027.format(fid_bad))"},{"type":"heading","level":2,"content":"CLIP-FID and Semantic Features"},{"type":"text","content":"Inception v3 was trained on ImageNet and its features are biased toward ImageNet categories. CLIP-FID (Kynkäänniemi et al. 2022) replaces the Inception pool3 features with CLIP ViT-L/14 features, which are more semantically meaningful and better aligned with human perception. CLIP-FID shows better correlation with human judgement, especially for text-conditional models and out-of-distribution images. The computation is identical to FID — only the feature extractor changes. For modern diffusion model evaluation, CLIP-FID is increasingly preferred over standard FID."},{"type":"heading","level":2,"content":"Precision and Recall for GANs"},{"type":"text","content":"Precision and Recall (Kynkäänniemi et al. 2019) decompose generation quality into two orthogonal aspects. Precision = fraction of generated samples that fall within the real data manifold (measures sample quality / fidelity). Recall = fraction of real samples that fall within the generated manifold (measures coverage / diversity). A mode-dropping GAN has high precision but low recall. A noisy GAN that generates blurry averages has low precision but potentially high recall. FID conflates both; P\u0026R separates them, enabling diagnosis of specific failure modes."},{"type":"code","language":"python","content":"import numpy as np\n\ndef precision_recall_manifold(real_feats, fake_feats, k=3):\n    \u0027\u0027\u0027Precision/Recall via k-NN manifold estimation (Kynkaanniemi 2019).\u0027\u0027\u0027\n    def knn_radius(feats, k):\n        # Squared pairwise distances\n        sq = np.sum((feats[:, None] - feats[None]) ** 2, axis=-1)\n        np.fill_diagonal(sq, np.inf)\n        return np.sort(sq, axis=1)[:, k-1]   # kth-NN squared dist\n\n    r_real = knn_radius(real_feats, k)   # each real sample\u0027s ball radius\n    r_fake = knn_radius(fake_feats, k)\n    # dist from each fake to every real\n    d_f2r  = np.sum((fake_feats[:, None] - real_feats[None])**2, axis=-1)\n    prec   = np.mean(np.any(d_f2r \u003c r_real[None], axis=1))  # fake in real ball?\n    # dist from each real to every fake\n    d_r2f  = d_f2r.T\n    rec    = np.mean(np.any(d_r2f \u003c r_fake[None], axis=1))  # real in fake ball?\n    return float(prec), float(rec)\n\nnp.random.seed(1)\nreal_f = np.random.randn(300, 64)\n# Good model: same distribution\nfake_good = np.random.randn(300, 64)\np1, r1 = precision_recall_manifold(real_f, fake_good)\nprint(\u0027Good model  -- Precision: {:.3f}  Recall: {:.3f}\u0027.format(p1, r1))\n# Mode drop: generate half the modes only\nfake_drop = np.random.randn(300, 64) * 0.5   # narrower distribution\np2, r2 = precision_recall_manifold(real_f, fake_drop)\nprint(\u0027Mode drop   -- Precision: {:.3f}  Recall: {:.3f}\u0027.format(p2, r2))"},{"type":"callout","variant":"warning","title":"FID Requires Large Sample Sizes","content":"FID is notoriously unstable at small sample counts. With N=1000 samples from identical distributions, FID can read 5–20 due to finite-sample noise in covariance estimation. The standard recommendation is N≥10000 for each of real and generated. Reporting FID with N\u003c5000 without confidence intervals is misleading. The bias of FID also depends on the feature dimensionality (2048 for Inception): the covariance matrix requires N \u003e\u003e 2048 samples to be well-conditioned."},{"type":"heading","level":2,"content":"Effect of Sample Size on FID Stability"},{"type":"text","content":"FID inflates dramatically at small N because the sample covariance is a poor estimate of the true covariance when N \u003c d (undersampled regime). At N=100 with d=2048, the covariance matrix is rank-deficient and FID is effectively meaningless. As N grows, FID converges to the population value. Plotting FID vs N for your model is a diagnostic tool: if FID is still changing significantly at N=10K, increase the sample count before reporting."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.linalg import sqrtm\n\ndef fid_vs_n(d=64, n_values=None):\n    \u0027\u0027\u0027FID between identical distributions at different sample sizes.\u0027\u0027\u0027\n    if n_values is None:\n        n_values = [50, 100, 500, 1000, 5000]\n    np.random.seed(42)\n    pop = np.random.randn(20000, d)\n    for N in n_values:\n        real_s = pop[:N]; fake_s = pop[N:2*N]\n        mu_r, sig_r = real_s.mean(0), np.cov(real_s, rowvar=False)\n        mu_f, sig_f = fake_s.mean(0), np.cov(fake_s, rowvar=False)\n        cm = sqrtm(sig_r @ sig_f)\n        cm = cm.real if np.iscomplexobj(cm) else cm\n        fid = float(np.dot(mu_r-mu_f, mu_r-mu_f) +\n                    np.trace(sig_r + sig_f - 2*cm))\n        print(\u0027N={:6d}  FID={:.1f}\u0027.format(N, fid))\n\nfid_vs_n(d=64)\nprint(\u0027FID inflates at small N even when real and fake distributions are identical!\u0027)"},{"type":"heading","level":2,"content":"Practical Guidance for GAN Evaluation"},{"type":"text","content":"Use FID as the primary metric but always report sample count and whether features are from Inception or CLIP. Report precision and recall when diagnosing mode collapse vs quality issues. IS is largely deprecated for conditional models — it does not penalise memorisation. CLIP-FID is preferred for text-conditional models. For paired translation (Pix2Pix), pixel-level metrics PSNR and SSIM against ground truth are most informative. Always compute metrics on a fixed held-out real set to enable fair comparison across checkpoints."},{"type":"list","ordered":false,"items":["FID: primary metric; use N\u003e=10000; lower is better; requires Inception or CLIP features.","IS: secondary; ignores real data; gameable; mostly deprecated for modern conditional models.","CLIP-FID: preferred for text-conditional and open-vocabulary generation tasks.","Precision: measures sample fidelity — are generated samples on the real manifold?","Recall: measures diversity coverage — does the generated manifold cover the real manifold?","PSNR/SSIM: only meaningful for paired translation where ground truth exists."]},{"type":"heading","level":2,"content":"Metric Comparison"},{"type":"table","headers":["Metric","What It Measures","Compares to Real Data","Sample Size Needed","Modern Preference"],"rows":[["IS","Quality + diversity via Inception labels","No","N\u003e=5000","Low (gameable, no real comparison)"],["FID","Feature distribution distance (Frechet)","Yes","N\u003e=10000","High — standard benchmark"],["CLIP-FID","FID with CLIP features (semantic)","Yes","N\u003e=10000","High for text-conditional models"],["Precision","Sample fidelity (fake in real manifold)","Yes","N\u003e=5000","Medium — use with Recall"],["Recall","Coverage diversity (real in fake manifold)","Yes","N\u003e=5000","Medium — use with Precision"]]},{"type":"divider"}]"
---
# GAN Evaluation — FID, IS, and Precision/Recall

Evaluating generative models is fundamentally harder than discriminative models: there is no held-out test set with labels, and visual quality is subjective. The field has converged on automatic metrics computed over large sample sets — primarily FID and IS — but each has failure modes. Understanding what each metric measures, what biases it has, and when it misleads is essential for correctly interpreting GAN training progress and comparing models across papers.

## Inception Score (IS)

IS (Salimans et al. 2016) measures two properties using a pretrained Inception v3 classifier: (1) quality — individual images should have confident (low-entropy) class predictions p(y|x); (2) diversity — the marginal p(y) = E_x[p(y|x)] should be uniform over classes. IS = exp(E_x[KL(p(y|x) ‖ p(y))]). Higher IS is better. Problems: IS does not compare generated images to real images at all — a model memorising the training set with perfect class balance achieves maximum IS. It is also sensitive to the Inception preprocessing and known to be gameable.

```python
import torch
import torch.nn as nn
import numpy as np

def inception_score(pyx_all, n_splits=10):
    '''IS from pre-extracted p(y|x) softmax probabilities.
    pyx_all: (N, C) numpy array of class probabilities.
    Returns (mean IS, std IS) across splits.'''
    N, C = pyx_all.shape
    split_sz = N // n_splits
    scores = []
    for i in range(n_splits):
        part = pyx_all[i*split_sz : (i+1)*split_sz]  # (M, C)
        py   = part.mean(axis=0, keepdims=True)        # marginal p(y)
        kl   = np.sum(part * (np.log(part + 1e-10) -
                              np.log(py   + 1e-10)), axis=1)  # per-sample KL
        scores.append(float(np.exp(kl.mean())))
    return float(np.mean(scores)), float(np.std(scores))

np.random.seed(42)
N, C = 1000, 10
# High-quality: peaked, diverse -> high IS
pyx_good = np.eye(C)[np.random.randint(0, C, N)] * 0.9 + 0.01
pyx_good /= pyx_good.sum(1, keepdims=True)
mean_is, std_is = inception_score(pyx_good)
print('High-quality IS: {:.2f} +/- {:.2f}'.format(mean_is, std_is))
# Low-diversity: all predict class 0
pyx_bad = np.zeros((N, C)); pyx_bad[:, 0] = 0.99; pyx_bad[:, 1:] = 0.01/9
mean_b, std_b = inception_score(pyx_bad)
print('Low-diversity IS: {:.2f} +/- {:.2f}'.format(mean_b, std_b))
```

## Fréchet Inception Distance (FID)

FID (Heusel et al. 2017) compares the distribution of real images to that of generated images using features extracted from Inception v3's pool3 layer (2048-d). Both sets of features are modelled as multivariate Gaussians; FID is the Fréchet distance between them: FID = ‖μ_r − μ_g‖² + Tr(Σ_r + Σ_g − 2(Σ_rΣ_g)^{1/2}). Lower FID means the generated distribution is closer to real. FID is sensitive to both quality (Σ mismatch from blurry images) and diversity (μ mismatch from mode collapse). Standard practice: use ≥10K generated and ≥10K real samples to stabilise the estimate.

```python
import numpy as np
from scipy.linalg import sqrtm

def frechet_distance(mu1, sigma1, mu2, sigma2, eps=1e-6):
    '''FID = ||mu1-mu2||^2 + Tr(sigma1 + sigma2 - 2*sqrtm(sigma1@sigma2)).'''
    diff = mu1 - mu2
    covmean, _ = sqrtm(sigma1 @ sigma2, disp=False)
    if not np.isfinite(covmean).all():
        offset = np.eye(sigma1.shape[0]) * eps
        covmean = sqrtm((sigma1 + offset) @ (sigma2 + offset))
    if np.iscomplexobj(covmean):
        covmean = covmean.real
    return float(diff @ diff + np.trace(sigma1 + sigma2 - 2*covmean))

np.random.seed(0)
d = 256   # reduced from 2048 for demo speed
N = 500
real_feats = np.random.randn(N, d)
# Same distribution -> FID near 0
fake_same = np.random.randn(N, d)
mu_r, sig_r = real_feats.mean(0), np.cov(real_feats, rowvar=False)
mu_s, sig_s = fake_same.mean(0),  np.cov(fake_same,  rowvar=False)
fid_good = frechet_distance(mu_r, sig_r, mu_s, sig_s)
print('FID (same dist): {:.2f}'.format(fid_good))
# Shifted distribution -> higher FID
fake_shift = np.random.randn(N, d) + 0.5
mu_sh, sig_sh = fake_shift.mean(0), np.cov(fake_shift, rowvar=False)
fid_bad = frechet_distance(mu_r, sig_r, mu_sh, sig_sh)
print('FID (shifted):   {:.2f}'.format(fid_bad))
```

## CLIP-FID and Semantic Features

Inception v3 was trained on ImageNet and its features are biased toward ImageNet categories. CLIP-FID (Kynkäänniemi et al. 2022) replaces the Inception pool3 features with CLIP ViT-L/14 features, which are more semantically meaningful and better aligned with human perception. CLIP-FID shows better correlation with human judgement, especially for text-conditional models and out-of-distribution images. The computation is identical to FID — only the feature extractor changes. For modern diffusion model evaluation, CLIP-FID is increasingly preferred over standard FID.

## Precision and Recall for GANs

Precision and Recall (Kynkäänniemi et al. 2019) decompose generation quality into two orthogonal aspects. Precision = fraction of generated samples that fall within the real data manifold (measures sample quality / fidelity). Recall = fraction of real samples that fall within the generated manifold (measures coverage / diversity). A mode-dropping GAN has high precision but low recall. A noisy GAN that generates blurry averages has low precision but potentially high recall. FID conflates both; P&R separates them, enabling diagnosis of specific failure modes.

```python
import numpy as np

def precision_recall_manifold(real_feats, fake_feats, k=3):
    '''Precision/Recall via k-NN manifold estimation (Kynkaanniemi 2019).'''
    def knn_radius(feats, k):
        # Squared pairwise distances
        sq = np.sum((feats[:, None] - feats[None]) ** 2, axis=-1)
        np.fill_diagonal(sq, np.inf)
        return np.sort(sq, axis=1)[:, k-1]   # kth-NN squared dist

    r_real = knn_radius(real_feats, k)   # each real sample's ball radius
    r_fake = knn_radius(fake_feats, k)
    # dist from each fake to every real
    d_f2r  = np.sum((fake_feats[:, None] - real_feats[None])**2, axis=-1)
    prec   = np.mean(np.any(d_f2r < r_real[None], axis=1))  # fake in real ball?
    # dist from each real to every fake
    d_r2f  = d_f2r.T
    rec    = np.mean(np.any(d_r2f < r_fake[None], axis=1))  # real in fake ball?
    return float(prec), float(rec)

np.random.seed(1)
real_f = np.random.randn(300, 64)
# Good model: same distribution
fake_good = np.random.randn(300, 64)
p1, r1 = precision_recall_manifold(real_f, fake_good)
print('Good model  -- Precision: {:.3f}  Recall: {:.3f}'.format(p1, r1))
# Mode drop: generate half the modes only
fake_drop = np.random.randn(300, 64) * 0.5   # narrower distribution
p2, r2 = precision_recall_manifold(real_f, fake_drop)
print('Mode drop   -- Precision: {:.3f}  Recall: {:.3f}'.format(p2, r2))
```

> **FID Requires Large Sample Sizes**: FID is notoriously unstable at small sample counts. With N=1000 samples from identical distributions, FID can read 5–20 due to finite-sample noise in covariance estimation. The standard recommendation is N≥10000 for each of real and generated. Reporting FID with N<5000 without confidence intervals is misleading. The bias of FID also depends on the feature dimensionality (2048 for Inception): the covariance matrix requires N >> 2048 samples to be well-conditioned.

## Effect of Sample Size on FID Stability

FID inflates dramatically at small N because the sample covariance is a poor estimate of the true covariance when N < d (undersampled regime). At N=100 with d=2048, the covariance matrix is rank-deficient and FID is effectively meaningless. As N grows, FID converges to the population value. Plotting FID vs N for your model is a diagnostic tool: if FID is still changing significantly at N=10K, increase the sample count before reporting.

```python
import numpy as np
from scipy.linalg import sqrtm

def fid_vs_n(d=64, n_values=None):
    '''FID between identical distributions at different sample sizes.'''
    if n_values is None:
        n_values = [50, 100, 500, 1000, 5000]
    np.random.seed(42)
    pop = np.random.randn(20000, d)
    for N in n_values:
        real_s = pop[:N]; fake_s = pop[N:2*N]
        mu_r, sig_r = real_s.mean(0), np.cov(real_s, rowvar=False)
        mu_f, sig_f = fake_s.mean(0), np.cov(fake_s, rowvar=False)
        cm = sqrtm(sig_r @ sig_f)
        cm = cm.real if np.iscomplexobj(cm) else cm
        fid = float(np.dot(mu_r-mu_f, mu_r-mu_f) +
                    np.trace(sig_r + sig_f - 2*cm))
        print('N={:6d}  FID={:.1f}'.format(N, fid))

fid_vs_n(d=64)
print('FID inflates at small N even when real and fake distributions are identical!')
```

## Practical Guidance for GAN Evaluation

Use FID as the primary metric but always report sample count and whether features are from Inception or CLIP. Report precision and recall when diagnosing mode collapse vs quality issues. IS is largely deprecated for conditional models — it does not penalise memorisation. CLIP-FID is preferred for text-conditional models. For paired translation (Pix2Pix), pixel-level metrics PSNR and SSIM against ground truth are most informative. Always compute metrics on a fixed held-out real set to enable fair comparison across checkpoints.

- FID: primary metric; use N>=10000; lower is better; requires Inception or CLIP features.
- IS: secondary; ignores real data; gameable; mostly deprecated for modern conditional models.
- CLIP-FID: preferred for text-conditional and open-vocabulary generation tasks.
- Precision: measures sample fidelity — are generated samples on the real manifold?
- Recall: measures diversity coverage — does the generated manifold cover the real manifold?
- PSNR/SSIM: only meaningful for paired translation where ground truth exists.

## Metric Comparison

| Metric | What It Measures | Compares to Real Data | Sample Size Needed | Modern Preference |
| --- | --- | --- | --- | --- |
| IS | Quality + diversity via Inception labels | No | N>=5000 | Low (gameable, no real comparison) |
| FID | Feature distribution distance (Frechet) | Yes | N>=10000 | High — standard benchmark |
| CLIP-FID | FID with CLIP features (semantic) | Yes | N>=10000 | High for text-conditional models |
| Precision | Sample fidelity (fake in real manifold) | Yes | N>=5000 | Medium — use with Recall |
| Recall | Coverage diversity (real in fake manifold) | Yes | N>=5000 | Medium — use with Precision |

---

