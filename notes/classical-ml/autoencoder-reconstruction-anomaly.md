---
title: "Autoencoder Reconstruction Error for Anomaly Detection"
slug: "autoencoder-reconstruction-anomaly"
description: "Train autoencoders on normal data and use reconstruction error as anomaly score — covering dense, CNN, and LSTM architectures with threshold selection strategies and memorization pitfalls."
tags: ["anomaly-detection", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Autoencoders learn a compressed representation of normal training data by encoding it into a low-dimensional latent space and decoding it back. Trained exclusively on normal data, the autoencoder learns the manifold of normal patterns. At test time, normal points reconstruct well (low error) while anomalies — which do not lie on the learned manifold — produce high reconstruction errors. The anomaly score is simply ‖x − decoder(encoder(x))‖²."},{"type":"heading","level":2,"content":"Reconstruction Error as Anomaly Score"},{"type":"text","content":"The autoencoder minimises reconstruction error over normal training data. The bottleneck (latent dimension \u003c input dimension) forces the model to learn a compact representation capturing only the main variance directions. Anomalies, by definition not well-represented by this compact code, produce high decoder error. The key parameters are latent dimension (smaller = more compression = higher sensitivity but more false positives) and architecture depth."},{"type":"math","display":true,"content":"\\text{score}(x) = \\|x - g(f(x))\\|^2, \\quad \\text{flag if score}(x) \u003e \\tau"},{"type":"heading","level":2,"content":"Dense Autoencoder for Tabular Data"},{"type":"text","content":"For tabular data, a dense (fully connected) autoencoder with 2-3 hidden layers and a bottleneck latent dimension of 2-8 is typically sufficient. Train only on normal data using Adam, mean-squared error loss, and early stopping on a held-out validation set of normal data. After training, compute per-sample reconstruction error on the full dataset to generate anomaly scores."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nfrom torch.utils.data import DataLoader, TensorDataset\n\nnp.random.seed(42); torch.manual_seed(42)\nX_normal  = np.random.normal(0, 1, (1000, 20)).astype(np.float32)\nX_anomaly = np.random.uniform(-4, 4, (50,  20)).astype(np.float32)\n\nclass Autoencoder(nn.Module):\n    def __init__(self, d_in, d_lat):\n        super().__init__()\n        self.enc = nn.Sequential(nn.Linear(d_in, 64), nn.ReLU(),\n                                  nn.Linear(64, d_lat), nn.ReLU())\n        self.dec = nn.Sequential(nn.Linear(d_lat, 64), nn.ReLU(),\n                                  nn.Linear(64, d_in))\n    def forward(self, x): return self.dec(self.enc(x))\n\nds  = TensorDataset(torch.tensor(X_normal))\ndl  = DataLoader(ds, batch_size=64, shuffle=True)\nmdl = Autoencoder(20, 4)\nopt = torch.optim.Adam(mdl.parameters(), lr=1e-3)\n\nfor epoch in range(50):\n    for (xb,) in dl:\n        loss = nn.functional.mse_loss(mdl(xb), xb)\n        opt.zero_grad(); loss.backward(); opt.step()\n\nmdl.eval()\nwith torch.no_grad():\n    Xn_t = torch.tensor(X_normal)\n    Xa_t = torch.tensor(X_anomaly)\n    err_n = nn.functional.mse_loss(mdl(Xn_t), Xn_t, reduction=\u0027none\u0027).mean(1).numpy()\n    err_a = nn.functional.mse_loss(mdl(Xa_t), Xa_t, reduction=\u0027none\u0027).mean(1).numpy()\nprint(f\u0027Normal  recon error: {err_n.mean():.3f} +/- {err_n.std():.3f}\u0027)\nprint(f\u0027Anomaly recon error: {err_a.mean():.3f} +/- {err_a.std():.3f}\u0027)"},{"type":"heading","level":2,"content":"Threshold Selection Strategies"},{"type":"text","content":"The threshold τ determines the precision-recall tradeoff. Common strategies: (1) fixed percentile of training errors (e.g., 95th or 99th percentile), (2) optimise F1 on a small labelled validation set, (3) fit extreme value theory (Gumbel) to training errors and use a return level, (4) PR-curve optimum for the target recall. Training percentile is the simplest and most common approach in practice."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.metrics import precision_recall_curve, average_precision_score\n\nnp.random.seed(42)\ntrain_errors  = np.random.exponential(scale=0.5, size=1000)\nnormal_test   = np.random.exponential(scale=0.5, size=200)\nanomaly_test  = np.random.exponential(scale=2.5, size=30)\ntest_errors   = np.concatenate([normal_test, anomaly_test])\ny_true        = np.array([0]*200 + [1]*30)\n\nprint(\u0027--- Percentile Thresholds ---\u0027)\nfor pct in [90, 95, 99]:\n    tau = np.percentile(train_errors, pct)\n    preds = (test_errors \u003e tau).astype(int)\n    prec = (preds \u0026 y_true).sum() / max(preds.sum(), 1)\n    rec  = (preds \u0026 y_true).sum() / y_true.sum()\n    f1   = 2*prec*rec/(prec+rec+1e-8)\n    print(f\u0027  P{pct}: tau={tau:.3f}  P={prec:.2f}  R={rec:.2f}  F1={f1:.2f}\u0027)\n\nprint(\u0027--- PR-Curve Optimal Threshold ---\u0027)\nprec_c, rec_c, thres = precision_recall_curve(y_true, test_errors)\nf1_c = 2*prec_c*rec_c/(prec_c+rec_c+1e-8)\nbest = np.argmax(f1_c)\nprint(f\u0027  tau={thres[best]:.3f}  P={prec_c[best]:.2f}  R={rec_c[best]:.2f}  F1={f1_c[best]:.2f}\u0027)\nap = average_precision_score(y_true, test_errors)\nprint(f\u0027  AUPRC: {ap:.3f}\u0027)"},{"type":"heading","level":2,"content":"CNN Autoencoder for Image Anomaly Detection"},{"type":"text","content":"For image data, convolutional autoencoders capture spatial structure more effectively than dense autoencoders. The encoder uses Conv2d + MaxPool2d to downsample; the decoder uses ConvTranspose2d to upsample back to original resolution. The reconstruction error is computed per-pixel and averaged. The bottleneck spatial resolution (not just channel count) controls compression: a 7×7 bottleneck for 28×28 images captures global structure only."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ntorch.manual_seed(42)\n\nclass ConvAE(nn.Module):\n    def __init__(self):\n        super().__init__()\n        self.enc = nn.Sequential(\n            nn.Conv2d(1, 16, 3, padding=1), nn.ReLU(), nn.MaxPool2d(2),\n            nn.Conv2d(16, 8, 3, padding=1), nn.ReLU(), nn.MaxPool2d(2)\n        )\n        self.dec = nn.Sequential(\n            nn.ConvTranspose2d(8, 16, 2, stride=2), nn.ReLU(),\n            nn.ConvTranspose2d(16, 1, 2, stride=2), nn.Sigmoid()\n        )\n    def forward(self, x): return self.dec(self.enc(x))\n\nmodel = ConvAE()\nopt   = torch.optim.Adam(model.parameters(), lr=1e-3)\n\nX_normal  = torch.zeros(200, 1, 28, 28) + 0.3*torch.randn(200, 1, 28, 28)\nX_anomaly = torch.rand(10, 1, 28, 28)\n\nfor _ in range(30):\n    rec  = model(X_normal)\n    loss = nn.functional.mse_loss(rec, X_normal)\n    opt.zero_grad(); loss.backward(); opt.step()\n\nmodel.eval()\nwith torch.no_grad():\n    err_n = nn.functional.mse_loss(model(X_normal),  X_normal,  reduction=\u0027none\u0027).mean([1,2,3])\n    err_a = nn.functional.mse_loss(model(X_anomaly), X_anomaly, reduction=\u0027none\u0027).mean([1,2,3])\nprint(f\u0027Normal  recon error: {err_n.mean():.4f} +/- {err_n.std():.4f}\u0027)\nprint(f\u0027Anomaly recon error: {err_a.mean():.4f} +/- {err_a.std():.4f}\u0027)\nprint(f\u0027Separation ratio: {err_a.mean()/err_n.mean():.1f}x\u0027)"},{"type":"heading","level":2,"content":"LSTM Autoencoder for Sequence Anomaly Detection"},{"type":"text","content":"For time-series and sequence data, LSTM autoencoders encode the full sequence into a fixed-size hidden state and decode it back to the original sequence. The encoder reads the sequence forward; the decoder receives the final hidden state repeated as input and generates the reconstruction. Training on normal sequences teaches the model temporal patterns; anomalous sequences with unusual dynamics produce high per-timestep reconstruction error."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ntorch.manual_seed(42)\nSEQ, FEAT = 30, 5\n\nclass LSTMAutoencoder(nn.Module):\n    def __init__(self, n_feat, latent=8):\n        super().__init__()\n        self.enc = nn.LSTM(n_feat,  latent, batch_first=True)\n        self.dec = nn.LSTM(latent, n_feat,  batch_first=True)\n    def forward(self, x):\n        _, (h, _) = self.enc(x)\n        h_rep = h.squeeze(0).unsqueeze(1).repeat(1, x.size(1), 1)\n        out, _ = self.dec(h_rep)\n        return out\n\nmodel = LSTMAutoencoder(FEAT)\nopt   = torch.optim.Adam(model.parameters(), lr=1e-3)\n\nt = torch.linspace(0, 6.28, SEQ)\nX_normal  = torch.stack([torch.stack([\n    torch.sin(t + i*0.5 + j) for j in range(FEAT)], dim=1) for i in range(300)])\nX_anomaly = torch.randn(20, SEQ, FEAT) * 3\n\nfor _ in range(40):\n    rec  = model(X_normal)\n    loss = nn.functional.mse_loss(rec, X_normal)\n    opt.zero_grad(); loss.backward(); opt.step()\n\nmodel.eval()\nwith torch.no_grad():\n    err_n = nn.functional.mse_loss(model(X_normal),  X_normal,  reduction=\u0027none\u0027).mean([1,2]).numpy()\n    err_a = nn.functional.mse_loss(model(X_anomaly), X_anomaly, reduction=\u0027none\u0027).mean([1,2]).numpy()\nprint(f\u0027Normal  seq error: {err_n.mean():.4f} +/- {err_n.std():.4f}\u0027)\nprint(f\u0027Anomaly seq error: {err_a.mean():.4f} +/- {err_a.std():.4f}\u0027)"},{"type":"heading","level":2,"content":"Threshold Methods Comparison"},{"type":"table","headers":["Method","Label Requirement","Calibration","Robustness","Recommended For"],"rows":[["Fixed percentile (P95/P99)","None (train errors only)","Simple — single parameter","Sensitive to train distribution","Quick baseline, no labelled anomalies"],["Validation set optimisation","Small labelled set needed","Optimises target metric (F1/AUPRC)","Good if val set is representative","When a few labelled anomalies are available"],["Extreme value theory (Gumbel)","None (train errors only)","Principled statistical model","Robust for rare extremes","When anomalies are rare and extreme"],["PR-curve optimum","Labelled test set required","Maximises F1 at target recall","Depends on test set quality","Evaluation and offline threshold selection"]]},{"type":"heading","level":2,"content":"Memorization Problem and Regularisation"},{"type":"text","content":"A powerful autoencoder (many layers, large latent dim) can memorise training data and generalise well even to anomalies, eliminating the score gap. Regularisation strategies to prevent this: (1) undercomplete architecture (small latent dim forces compression), (2) sparse autoencoder (L1 penalty on latent activations), (3) denoising autoencoder (train to remove noise — anomalies cannot be denoised), (4) dropout in encoder/decoder, (5) early stopping before the model overfits."},{"type":"callout","variant":"warning","title":"Memorisation Risk","content":"If the validation reconstruction error stops decreasing but the gap between normal and anomaly scores collapses, the model is memorising rather than generalising. Use early stopping monitored on a validation set of normal data, and ensure the latent dimension is much smaller than the input dimension (rule of thumb: latent_dim \u003c 0.2 * input_dim for tabular data)."},{"type":"list","ordered":false,"items":["Use the 95th or 99th percentile of train reconstruction errors as the initial threshold","Always visualise the score histograms for normal and anomalous points to check separation","For image data, also inspect worst-reconstructed images qualitatively","Denoising autoencoders are more robust to memorisation than standard autoencoders","AUPRC (area under precision-recall curve) is the right evaluation metric for imbalanced anomaly detection"]}]"
---
# Autoencoder Reconstruction Error for Anomaly Detection

Autoencoders learn a compressed representation of normal training data by encoding it into a low-dimensional latent space and decoding it back. Trained exclusively on normal data, the autoencoder learns the manifold of normal patterns. At test time, normal points reconstruct well (low error) while anomalies — which do not lie on the learned manifold — produce high reconstruction errors. The anomaly score is simply ‖x − decoder(encoder(x))‖².

## Reconstruction Error as Anomaly Score

The autoencoder minimises reconstruction error over normal training data. The bottleneck (latent dimension < input dimension) forces the model to learn a compact representation capturing only the main variance directions. Anomalies, by definition not well-represented by this compact code, produce high decoder error. The key parameters are latent dimension (smaller = more compression = higher sensitivity but more false positives) and architecture depth.

$$\text{score}(x) = \|x - g(f(x))\|^2, \quad \text{flag if score}(x) > \tau$$

## Dense Autoencoder for Tabular Data

For tabular data, a dense (fully connected) autoencoder with 2-3 hidden layers and a bottleneck latent dimension of 2-8 is typically sufficient. Train only on normal data using Adam, mean-squared error loss, and early stopping on a held-out validation set of normal data. After training, compute per-sample reconstruction error on the full dataset to generate anomaly scores.

```python
import numpy as np
import torch
import torch.nn as nn
from torch.utils.data import DataLoader, TensorDataset

np.random.seed(42); torch.manual_seed(42)
X_normal  = np.random.normal(0, 1, (1000, 20)).astype(np.float32)
X_anomaly = np.random.uniform(-4, 4, (50,  20)).astype(np.float32)

class Autoencoder(nn.Module):
    def __init__(self, d_in, d_lat):
        super().__init__()
        self.enc = nn.Sequential(nn.Linear(d_in, 64), nn.ReLU(),
                                  nn.Linear(64, d_lat), nn.ReLU())
        self.dec = nn.Sequential(nn.Linear(d_lat, 64), nn.ReLU(),
                                  nn.Linear(64, d_in))
    def forward(self, x): return self.dec(self.enc(x))

ds  = TensorDataset(torch.tensor(X_normal))
dl  = DataLoader(ds, batch_size=64, shuffle=True)
mdl = Autoencoder(20, 4)
opt = torch.optim.Adam(mdl.parameters(), lr=1e-3)

for epoch in range(50):
    for (xb,) in dl:
        loss = nn.functional.mse_loss(mdl(xb), xb)
        opt.zero_grad(); loss.backward(); opt.step()

mdl.eval()
with torch.no_grad():
    Xn_t = torch.tensor(X_normal)
    Xa_t = torch.tensor(X_anomaly)
    err_n = nn.functional.mse_loss(mdl(Xn_t), Xn_t, reduction='none').mean(1).numpy()
    err_a = nn.functional.mse_loss(mdl(Xa_t), Xa_t, reduction='none').mean(1).numpy()
print(f'Normal  recon error: {err_n.mean():.3f} +/- {err_n.std():.3f}')
print(f'Anomaly recon error: {err_a.mean():.3f} +/- {err_a.std():.3f}')
```

## Threshold Selection Strategies

The threshold τ determines the precision-recall tradeoff. Common strategies: (1) fixed percentile of training errors (e.g., 95th or 99th percentile), (2) optimise F1 on a small labelled validation set, (3) fit extreme value theory (Gumbel) to training errors and use a return level, (4) PR-curve optimum for the target recall. Training percentile is the simplest and most common approach in practice.

```python
import numpy as np
from sklearn.metrics import precision_recall_curve, average_precision_score

np.random.seed(42)
train_errors  = np.random.exponential(scale=0.5, size=1000)
normal_test   = np.random.exponential(scale=0.5, size=200)
anomaly_test  = np.random.exponential(scale=2.5, size=30)
test_errors   = np.concatenate([normal_test, anomaly_test])
y_true        = np.array([0]*200 + [1]*30)

print('--- Percentile Thresholds ---')
for pct in [90, 95, 99]:
    tau = np.percentile(train_errors, pct)
    preds = (test_errors > tau).astype(int)
    prec = (preds & y_true).sum() / max(preds.sum(), 1)
    rec  = (preds & y_true).sum() / y_true.sum()
    f1   = 2*prec*rec/(prec+rec+1e-8)
    print(f'  P{pct}: tau={tau:.3f}  P={prec:.2f}  R={rec:.2f}  F1={f1:.2f}')

print('--- PR-Curve Optimal Threshold ---')
prec_c, rec_c, thres = precision_recall_curve(y_true, test_errors)
f1_c = 2*prec_c*rec_c/(prec_c+rec_c+1e-8)
best = np.argmax(f1_c)
print(f'  tau={thres[best]:.3f}  P={prec_c[best]:.2f}  R={rec_c[best]:.2f}  F1={f1_c[best]:.2f}')
ap = average_precision_score(y_true, test_errors)
print(f'  AUPRC: {ap:.3f}')
```

## CNN Autoencoder for Image Anomaly Detection

For image data, convolutional autoencoders capture spatial structure more effectively than dense autoencoders. The encoder uses Conv2d + MaxPool2d to downsample; the decoder uses ConvTranspose2d to upsample back to original resolution. The reconstruction error is computed per-pixel and averaged. The bottleneck spatial resolution (not just channel count) controls compression: a 7×7 bottleneck for 28×28 images captures global structure only.

```python
import torch
import torch.nn as nn
import numpy as np

torch.manual_seed(42)

class ConvAE(nn.Module):
    def __init__(self):
        super().__init__()
        self.enc = nn.Sequential(
            nn.Conv2d(1, 16, 3, padding=1), nn.ReLU(), nn.MaxPool2d(2),
            nn.Conv2d(16, 8, 3, padding=1), nn.ReLU(), nn.MaxPool2d(2)
        )
        self.dec = nn.Sequential(
            nn.ConvTranspose2d(8, 16, 2, stride=2), nn.ReLU(),
            nn.ConvTranspose2d(16, 1, 2, stride=2), nn.Sigmoid()
        )
    def forward(self, x): return self.dec(self.enc(x))

model = ConvAE()
opt   = torch.optim.Adam(model.parameters(), lr=1e-3)

X_normal  = torch.zeros(200, 1, 28, 28) + 0.3*torch.randn(200, 1, 28, 28)
X_anomaly = torch.rand(10, 1, 28, 28)

for _ in range(30):
    rec  = model(X_normal)
    loss = nn.functional.mse_loss(rec, X_normal)
    opt.zero_grad(); loss.backward(); opt.step()

model.eval()
with torch.no_grad():
    err_n = nn.functional.mse_loss(model(X_normal),  X_normal,  reduction='none').mean([1,2,3])
    err_a = nn.functional.mse_loss(model(X_anomaly), X_anomaly, reduction='none').mean([1,2,3])
print(f'Normal  recon error: {err_n.mean():.4f} +/- {err_n.std():.4f}')
print(f'Anomaly recon error: {err_a.mean():.4f} +/- {err_a.std():.4f}')
print(f'Separation ratio: {err_a.mean()/err_n.mean():.1f}x')
```

## LSTM Autoencoder for Sequence Anomaly Detection

For time-series and sequence data, LSTM autoencoders encode the full sequence into a fixed-size hidden state and decode it back to the original sequence. The encoder reads the sequence forward; the decoder receives the final hidden state repeated as input and generates the reconstruction. Training on normal sequences teaches the model temporal patterns; anomalous sequences with unusual dynamics produce high per-timestep reconstruction error.

```python
import torch
import torch.nn as nn
import numpy as np

torch.manual_seed(42)
SEQ, FEAT = 30, 5

class LSTMAutoencoder(nn.Module):
    def __init__(self, n_feat, latent=8):
        super().__init__()
        self.enc = nn.LSTM(n_feat,  latent, batch_first=True)
        self.dec = nn.LSTM(latent, n_feat,  batch_first=True)
    def forward(self, x):
        _, (h, _) = self.enc(x)
        h_rep = h.squeeze(0).unsqueeze(1).repeat(1, x.size(1), 1)
        out, _ = self.dec(h_rep)
        return out

model = LSTMAutoencoder(FEAT)
opt   = torch.optim.Adam(model.parameters(), lr=1e-3)

t = torch.linspace(0, 6.28, SEQ)
X_normal  = torch.stack([torch.stack([
    torch.sin(t + i*0.5 + j) for j in range(FEAT)], dim=1) for i in range(300)])
X_anomaly = torch.randn(20, SEQ, FEAT) * 3

for _ in range(40):
    rec  = model(X_normal)
    loss = nn.functional.mse_loss(rec, X_normal)
    opt.zero_grad(); loss.backward(); opt.step()

model.eval()
with torch.no_grad():
    err_n = nn.functional.mse_loss(model(X_normal),  X_normal,  reduction='none').mean([1,2]).numpy()
    err_a = nn.functional.mse_loss(model(X_anomaly), X_anomaly, reduction='none').mean([1,2]).numpy()
print(f'Normal  seq error: {err_n.mean():.4f} +/- {err_n.std():.4f}')
print(f'Anomaly seq error: {err_a.mean():.4f} +/- {err_a.std():.4f}')
```

## Threshold Methods Comparison

| Method | Label Requirement | Calibration | Robustness | Recommended For |
| --- | --- | --- | --- | --- |
| Fixed percentile (P95/P99) | None (train errors only) | Simple — single parameter | Sensitive to train distribution | Quick baseline, no labelled anomalies |
| Validation set optimisation | Small labelled set needed | Optimises target metric (F1/AUPRC) | Good if val set is representative | When a few labelled anomalies are available |
| Extreme value theory (Gumbel) | None (train errors only) | Principled statistical model | Robust for rare extremes | When anomalies are rare and extreme |
| PR-curve optimum | Labelled test set required | Maximises F1 at target recall | Depends on test set quality | Evaluation and offline threshold selection |

## Memorization Problem and Regularisation

A powerful autoencoder (many layers, large latent dim) can memorise training data and generalise well even to anomalies, eliminating the score gap. Regularisation strategies to prevent this: (1) undercomplete architecture (small latent dim forces compression), (2) sparse autoencoder (L1 penalty on latent activations), (3) denoising autoencoder (train to remove noise — anomalies cannot be denoised), (4) dropout in encoder/decoder, (5) early stopping before the model overfits.

> **Memorisation Risk**: If the validation reconstruction error stops decreasing but the gap between normal and anomaly scores collapses, the model is memorising rather than generalising. Use early stopping monitored on a validation set of normal data, and ensure the latent dimension is much smaller than the input dimension (rule of thumb: latent_dim < 0.2 * input_dim for tabular data).

- Use the 95th or 99th percentile of train reconstruction errors as the initial threshold
- Always visualise the score histograms for normal and anomalous points to check separation
- For image data, also inspect worst-reconstructed images qualitatively
- Denoising autoencoders are more robust to memorisation than standard autoencoders
- AUPRC (area under precision-recall curve) is the right evaluation metric for imbalanced anomaly detection

