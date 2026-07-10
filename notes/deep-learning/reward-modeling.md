---
title: "Reward Modeling — Bradley-Terry Model and Pairwise Preference Learning"
slug: "reward-modeling"
description: "Covers reward model training on pairwise preference data using the Bradley-Terry model and log-sigmoid loss, RM architecture (pretrained LLM backbone with scalar head), preference dataset creation from human comparisons, pairwise accuracy and margin evaluation, reward hacking detection via score distribution monitoring, and comparison of InstructGPT, Anthropic, Llama-3, Zephyr, and Nemotron reward models."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"A reward model (RM) is a neural network trained to predict which of two responses a human would prefer, given the same prompt. It converts qualitative human judgements into a scalar signal that downstream training (RLHF, best-of-N sampling) can optimise. The RM is the critical bottleneck in the RLHF pipeline: its errors compound — a biased RM produces biased policy updates, and the policy is then trained to exploit RM weaknesses (reward hacking). Understanding the Bradley-Terry loss, RM architecture, data collection, evaluation, and bias mitigation is essential for anyone building RLHF or preference-learning systems."},{"type":"heading","level":2,"content":"Bradley-Terry Model and Pairwise Loss"},{"type":"text","content":"The Bradley-Terry model provides a principled probabilistic foundation for pairwise preference learning. Given prompt x, chosen response y_w, and rejected response y_l, the probability that a human prefers y_w is modelled as P(y_w \u003e y_l | x) = σ(r(x, y_w) − r(x, y_l)) where σ is the sigmoid function and r is the scalar reward function. The RM loss is the negative log-likelihood of observed preferences: L = −E[log σ(r_w − r_l)]. Minimising this loss pushes r(x, y_w) to be larger than r(x, y_l) by an amount proportional to how confidently the model assigns the preference. The margin r_w − r_l is the key quantity: large positive margins indicate high-confidence correct preferences."},{"type":"heading","level":2,"content":"Reward Model Architecture"},{"type":"text","content":"The RM is initialised from a pretrained LLM (often the SFT model) with its language modelling head replaced by a single linear layer that outputs a scalar reward. The backbone processes the full prompt-plus-response sequence, and the scalar head pools the final hidden state at the last non-padding token position. Using the last token captures the cumulative context of the entire response. Initialising from the SFT model (rather than the raw pretrained model) is important — the SFT model already speaks instruction-following language, so it requires less data to learn preference distinctions. RM size typically matches or is larger than the policy model to act as an accurate critic."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\n\nclass RewardModel(nn.Module):\n    def __init__(self, base_model_name, dtype=torch.bfloat16):\n        super().__init__()\n        self.backbone = AutoModelForCausalLM.from_pretrained(base_model_name, torch_dtype=dtype)\n        d_model = self.backbone.config.hidden_size\n        self.backbone.lm_head = nn.Identity()  # remove token prediction head\n        self.reward_head = nn.Linear(d_model, 1, bias=False)\n\n    def forward(self, input_ids, attention_mask):\n        out = self.backbone(input_ids=input_ids, attention_mask=attention_mask, output_hidden_states=True)\n        last_hidden = out.hidden_states[-1]          # (B, T, d_model)\n        seq_lens = attention_mask.sum(dim=1) - 1    # index of last real token\n        batch_idx = torch.arange(last_hidden.size(0), device=last_hidden.device)\n        pooled = last_hidden[batch_idx, seq_lens]   # (B, d_model)\n        return self.reward_head(pooled).squeeze(-1) # (B,)\n\ndef bradley_terry_loss(r_chosen, r_rejected):\n    \"\"\"L = -E[log sigma(r_w - r_l)], the pairwise Bradley-Terry loss.\"\"\"\n    return -torch.nn.functional.logsigmoid(r_chosen - r_rejected).mean()\n\ndef rm_train_step(model, chosen_batch, rejected_batch, optimizer):\n    r_w = model(**chosen_batch)\n    r_l = model(**rejected_batch)\n    loss = bradley_terry_loss(r_w, r_l)\n    optimizer.zero_grad()\n    loss.backward()\n    torch.nn.utils.clip_grad_norm_(model.parameters(), 1.0)\n    optimizer.step()\n    accuracy = (r_w \u003e r_l).float().mean().item()\n    margin   = (r_w - r_l).mean().item()\n    return {\"loss\": loss.item(), \"accuracy\": accuracy, \"margin\": margin}"},{"type":"heading","level":2,"content":"Preference Dataset Creation"},{"type":"text","content":"RM training requires pairwise comparison data: for each prompt, at least two responses are generated and a human labeller selects the preferred one. In practice, labellers compare 2–8 completions per prompt and rank them — this yields O(k²) pairs from k completions, making comparison more efficient than absolute scoring. Labeller agreement is typically 70–80% (inter-annotator agreement), setting the upper bound on RM accuracy. The Anthropic HH-RLHF dataset (helpfulness + harmlessness) and OpenAI\u0027s InstructGPT comparisons are the most widely used public datasets. Data scale ranges from 10K pairs (small internal RM) to 1M+ (production systems like InstructGPT or Claude\u0027s RM)."},{"type":"code","language":"python","content":"from datasets import load_dataset\nfrom transformers import AutoTokenizer\nimport torch\n\ndef format_preference_pair(tokenizer, prompt, chosen, rejected, max_length=512):\n    \"\"\"Tokenize chosen and rejected responses for Bradley-Terry RM training.\"\"\"\n    def encode(response):\n        text = f\"Human: {prompt}\\n\\nAssistant: {response}\"\n        enc  = tokenizer(text, max_length=max_length, truncation=True,\n                         padding=\"max_length\", return_tensors=\"pt\")\n        return enc[\"input_ids\"][0], enc[\"attention_mask\"][0]\n\n    chosen_ids,   chosen_mask   = encode(chosen)\n    rejected_ids, rejected_mask = encode(rejected)\n    return {\n        \"chosen_input_ids\":       chosen_ids,\n        \"chosen_attention_mask\":  chosen_mask,\n        \"rejected_input_ids\":     rejected_ids,\n        \"rejected_attention_mask\": rejected_mask,\n    }\n\ntokenizer = AutoTokenizer.from_pretrained(\"meta-llama/Llama-3-8B\")\ntokenizer.pad_token = tokenizer.eos_token\n\ndataset = load_dataset(\"Anthropic/hh-rlhf\", split=\"train[:5000]\")\n\ndef preprocess(ex):\n    # HH-RLHF format: chosen and rejected are full conversation strings\n    prompt   = ex[\"chosen\"].rsplit(\"Assistant:\", 1)[0].strip()\n    chosen_r = ex[\"chosen\"].rsplit(\"Assistant:\", 1)[-1].strip()\n    rejected_r = ex[\"rejected\"].rsplit(\"Assistant:\", 1)[-1].strip()\n    return format_preference_pair(tokenizer, prompt, chosen_r, rejected_r)\n\ntokenized = dataset.map(preprocess, remove_columns=dataset.column_names)\nprint(f\"Preference pairs tokenized: {len(tokenized)}\")"},{"type":"heading","level":2,"content":"RM Evaluation — Accuracy, Margin, and Calibration"},{"type":"text","content":"The primary RM evaluation metric is pairwise accuracy: the fraction of held-out pairs where the RM assigns a higher reward to the chosen response. Random chance is 50%; a well-trained RM achieves 70–85% depending on data quality and model size. The mean reward margin (r_w − r_l) measures separability — larger margins indicate more confident, calibrated predictions. Calibration assessment checks whether the RM\u0027s win probability σ(r_w − r_l) matches empirical win rates: a RM predicting 80% win rate should be correct 80% of the time. RewardBench is the standard benchmark for comparing RMs across helpfulness, safety, and reasoning axes."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef evaluate_reward_model(model, eval_loader, device=\"cuda\"):\n    \"\"\"Compute pairwise accuracy, mean margin, and score distribution statistics.\"\"\"\n    model.eval()\n    r_chosen_all, r_rejected_all = [], []\n    with torch.no_grad():\n        for batch in eval_loader:\n            r_w = model(\n                input_ids=batch[\"chosen_input_ids\"].to(device),\n                attention_mask=batch[\"chosen_attention_mask\"].to(device)\n            )\n            r_l = model(\n                input_ids=batch[\"rejected_input_ids\"].to(device),\n                attention_mask=batch[\"rejected_attention_mask\"].to(device)\n            )\n            r_chosen_all.extend(r_w.cpu().float().tolist())\n            r_rejected_all.extend(r_l.cpu().float().tolist())\n    rw = np.array(r_chosen_all)\n    rl = np.array(r_rejected_all)\n    accuracy  = float((rw \u003e rl).mean())\n    margin    = float((rw - rl).mean())\n    overlap   = float((rw \u003c rl).mean())  # fraction where RM is wrong\n    print(f\"Pairwise accuracy : {accuracy:.3f}\")\n    print(f\"Mean margin       : {margin:.3f}\")\n    print(f\"Chosen  — mean: {rw.mean():.3f}, std: {rw.std():.3f}\")\n    print(f\"Rejected — mean: {rl.mean():.3f}, std: {rl.std():.3f}\")\n    print(f\"RM error rate     : {overlap:.3f}\")\n    return {\"accuracy\": accuracy, \"margin\": margin}"},{"type":"heading","level":2,"content":"Reward Hacking Detection"},{"type":"text","content":"Reward hacking occurs when the policy being trained by RLHF learns to exploit spurious features that the RM has overfit: verbose responses, particular sentence openers, or formatting patterns that correlate with high reward but not genuine quality. Detection requires monitoring the reward score distribution across training iterations — reward hacking manifests as monotonic score inflation without corresponding quality improvement. Ensemble RMs (averaging across 3–5 independently trained RMs) reduce hacking by making it harder to simultaneously exploit all models. KL-divergence regularisation (penalising divergence from the SFT policy) bounds how far the policy can exploit the RM before the KL penalty dominates."},{"type":"code","language":"python","content":"import numpy as np\n\nclass RewardHackingMonitor:\n    \"\"\"Track reward distribution across RL training to detect score inflation.\"\"\"\n\n    def __init__(self, baseline_window=50, detection_window=20, z_threshold=3.0):\n        self.history = []  # list of (step, mean, std)\n        self.baseline_window  = baseline_window\n        self.detection_window = detection_window\n        self.z_threshold = z_threshold\n\n    def record(self, step, rewards):\n        self.history.append((step, float(np.mean(rewards)), float(np.std(rewards))))\n\n    def detect_inflation(self):\n        if len(self.history) \u003c self.baseline_window + self.detection_window:\n            return False\n        means = [h[1] for h in self.history]\n        baseline = np.array(means[:self.baseline_window])\n        recent   = np.array(means[-self.detection_window:])\n        z = (recent.mean() - baseline.mean()) / (baseline.std() + 1e-8)\n        inflating = z \u003e self.z_threshold\n        print(f\"Baseline mean: {baseline.mean():.3f}  Recent mean: {recent.mean():.3f}  Z={z:.2f}\")\n        if inflating:\n            print(f\"[WARNING] Reward inflation detected (Z={z:.2f} \u003e {self.z_threshold}) — possible reward hacking\")\n        return inflating\n\n# Simulate training with gradual reward inflation\nmonitor = RewardHackingMonitor(baseline_window=50, detection_window=20)\nfor step in range(150):\n    rewards = np.random.normal(0.5 + step * 0.012, 0.3, size=32)\n    monitor.record(step, rewards)\nmonitor.detect_inflation()"},{"type":"heading","level":2,"content":"Reward Model Characteristics Comparison"},{"type":"table","headers":["Model","Size","Training Data","Pairwise Accuracy","Notable Bias / Notes"],"rows":[["InstructGPT RM (OpenAI)","6B","50K human comparisons, 2–7 completions/prompt","~70% held-out","Length bias; human labeller agreement ~72%"],["Anthropic (Claude) RM","52B","500K+ HH-RLHF helpfulness + harmlessness pairs","~75%","Helpfulness-harmlessness trade-off explicitly modelled"],["Llama-3 RM (Meta)","70B","Proprietary human + synthetic preference pairs","~80% (Arena)","Length bias reduced via normalisation; strong on reasoning"],["Zephyr RLAIF RM","7B","AI Feedback — Claude as labeller (UltraFeedback)","~65%","Less length bias; bounded by LLM judge quality ceiling"],["Nemotron-4-340B-Reward","340B","Proprietary large-scale synthetic preferences","~82% (RewardBench)","Near human-agreement; best open published RM as of 2024"]]},{"type":"heading","level":2,"content":"DPO, Implicit Rewards, and Bypassing the RM"},{"type":"text","content":"Direct Preference Optimisation (DPO) bypasses explicit RM training entirely. It shows that the optimal RLHF policy has a closed-form expression in terms of the preference data, allowing direct policy optimisation from pairwise comparisons. The DPO loss is L_DPO = −log σ(β log(π_θ(y_w|x)/π_ref(y_w|x)) − β log(π_θ(y_l|x)/π_ref(y_l|x))), which implicitly defines a reward r(x,y) = β log(π_θ(y|x)/π_ref(y|x)). DPO eliminates RM training overhead and avoids reward hacking (there is no separate RM to hack), but requires the preference data to be high quality since the policy is trained directly on it. Hybrid approaches like IPO and KTO extend DPO to handle label noise and non-pairwise data."},{"type":"list","ordered":false,"items":["RLHF pipeline: SFT → RM training on human pairs → PPO optimisation with KL penalty → evaluate with RM.","DPO shortcut: SFT → DPO directly on preference pairs — no RM, no PPO, half the training stages.","Best-of-N sampling: generate N responses, re-rank with RM, select the top-scoring one — inference-time reward hacking.","RM ensemble: train 3–5 RMs on different data splits, average rewards — reduces hacking surface area significantly.","Length normalisation: divide reward by response length (in tokens) to penalise verbosity bias in the RM signal.","Reward model calibration: check that σ(r_w - r_l) matches empirical win rate on held-out data via reliability diagrams."]},{"type":"callout","variant":"warning","title":"Length Bias in Reward Models","content":"Length bias in reward models is pervasive — RMs trained on human preferences systematically rate longer responses higher even when shorter responses are more accurate. Always check reward vs length correlation and use length-normalised scoring. A simple test: generate two versions of each response (short and verbose) and check if the RM consistently prefers the longer one regardless of content quality."},{"type":"text","content":"Reward modelling is the most data-sensitive component of the RLHF pipeline. The RM quality ceiling is set by human labeller agreement (~72–80%), so investing in labeller training, clear annotation guidelines, and careful prompt design pays large dividends. Monitoring reward score distributions throughout RL training (not just at the end) is essential for catching reward hacking before it corrupts the policy. For teams without the budget for large-scale human annotation, RLAIF (using a strong LLM as the preference labeller) or DPO with public preference datasets (UltraFeedback, HH-RLHF) are viable alternatives that approach RM quality within 5–10 percentage points."},{"type":"divider"}]"
---
# Reward Modeling — Bradley-Terry Model and Pairwise Preference Learning

A reward model (RM) is a neural network trained to predict which of two responses a human would prefer, given the same prompt. It converts qualitative human judgements into a scalar signal that downstream training (RLHF, best-of-N sampling) can optimise. The RM is the critical bottleneck in the RLHF pipeline: its errors compound — a biased RM produces biased policy updates, and the policy is then trained to exploit RM weaknesses (reward hacking). Understanding the Bradley-Terry loss, RM architecture, data collection, evaluation, and bias mitigation is essential for anyone building RLHF or preference-learning systems.

## Bradley-Terry Model and Pairwise Loss

The Bradley-Terry model provides a principled probabilistic foundation for pairwise preference learning. Given prompt x, chosen response y_w, and rejected response y_l, the probability that a human prefers y_w is modelled as P(y_w > y_l | x) = σ(r(x, y_w) − r(x, y_l)) where σ is the sigmoid function and r is the scalar reward function. The RM loss is the negative log-likelihood of observed preferences: L = −E[log σ(r_w − r_l)]. Minimising this loss pushes r(x, y_w) to be larger than r(x, y_l) by an amount proportional to how confidently the model assigns the preference. The margin r_w − r_l is the key quantity: large positive margins indicate high-confidence correct preferences.

## Reward Model Architecture

The RM is initialised from a pretrained LLM (often the SFT model) with its language modelling head replaced by a single linear layer that outputs a scalar reward. The backbone processes the full prompt-plus-response sequence, and the scalar head pools the final hidden state at the last non-padding token position. Using the last token captures the cumulative context of the entire response. Initialising from the SFT model (rather than the raw pretrained model) is important — the SFT model already speaks instruction-following language, so it requires less data to learn preference distinctions. RM size typically matches or is larger than the policy model to act as an accurate critic.

```python
import torch
import torch.nn as nn
from transformers import AutoModelForCausalLM, AutoTokenizer

class RewardModel(nn.Module):
    def __init__(self, base_model_name, dtype=torch.bfloat16):
        super().__init__()
        self.backbone = AutoModelForCausalLM.from_pretrained(base_model_name, torch_dtype=dtype)
        d_model = self.backbone.config.hidden_size
        self.backbone.lm_head = nn.Identity()  # remove token prediction head
        self.reward_head = nn.Linear(d_model, 1, bias=False)

    def forward(self, input_ids, attention_mask):
        out = self.backbone(input_ids=input_ids, attention_mask=attention_mask, output_hidden_states=True)
        last_hidden = out.hidden_states[-1]          # (B, T, d_model)
        seq_lens = attention_mask.sum(dim=1) - 1    # index of last real token
        batch_idx = torch.arange(last_hidden.size(0), device=last_hidden.device)
        pooled = last_hidden[batch_idx, seq_lens]   # (B, d_model)
        return self.reward_head(pooled).squeeze(-1) # (B,)

def bradley_terry_loss(r_chosen, r_rejected):
    """L = -E[log sigma(r_w - r_l)], the pairwise Bradley-Terry loss."""
    return -torch.nn.functional.logsigmoid(r_chosen - r_rejected).mean()

def rm_train_step(model, chosen_batch, rejected_batch, optimizer):
    r_w = model(**chosen_batch)
    r_l = model(**rejected_batch)
    loss = bradley_terry_loss(r_w, r_l)
    optimizer.zero_grad()
    loss.backward()
    torch.nn.utils.clip_grad_norm_(model.parameters(), 1.0)
    optimizer.step()
    accuracy = (r_w > r_l).float().mean().item()
    margin   = (r_w - r_l).mean().item()
    return {"loss": loss.item(), "accuracy": accuracy, "margin": margin}
```

## Preference Dataset Creation

RM training requires pairwise comparison data: for each prompt, at least two responses are generated and a human labeller selects the preferred one. In practice, labellers compare 2–8 completions per prompt and rank them — this yields O(k²) pairs from k completions, making comparison more efficient than absolute scoring. Labeller agreement is typically 70–80% (inter-annotator agreement), setting the upper bound on RM accuracy. The Anthropic HH-RLHF dataset (helpfulness + harmlessness) and OpenAI's InstructGPT comparisons are the most widely used public datasets. Data scale ranges from 10K pairs (small internal RM) to 1M+ (production systems like InstructGPT or Claude's RM).

```python
from datasets import load_dataset
from transformers import AutoTokenizer
import torch

def format_preference_pair(tokenizer, prompt, chosen, rejected, max_length=512):
    """Tokenize chosen and rejected responses for Bradley-Terry RM training."""
    def encode(response):
        text = f"Human: {prompt}\n\nAssistant: {response}"
        enc  = tokenizer(text, max_length=max_length, truncation=True,
                         padding="max_length", return_tensors="pt")
        return enc["input_ids"][0], enc["attention_mask"][0]

    chosen_ids,   chosen_mask   = encode(chosen)
    rejected_ids, rejected_mask = encode(rejected)
    return {
        "chosen_input_ids":       chosen_ids,
        "chosen_attention_mask":  chosen_mask,
        "rejected_input_ids":     rejected_ids,
        "rejected_attention_mask": rejected_mask,
    }

tokenizer = AutoTokenizer.from_pretrained("meta-llama/Llama-3-8B")
tokenizer.pad_token = tokenizer.eos_token

dataset = load_dataset("Anthropic/hh-rlhf", split="train[:5000]")

def preprocess(ex):
    # HH-RLHF format: chosen and rejected are full conversation strings
    prompt   = ex["chosen"].rsplit("Assistant:", 1)[0].strip()
    chosen_r = ex["chosen"].rsplit("Assistant:", 1)[-1].strip()
    rejected_r = ex["rejected"].rsplit("Assistant:", 1)[-1].strip()
    return format_preference_pair(tokenizer, prompt, chosen_r, rejected_r)

tokenized = dataset.map(preprocess, remove_columns=dataset.column_names)
print(f"Preference pairs tokenized: {len(tokenized)}")
```

## RM Evaluation — Accuracy, Margin, and Calibration

The primary RM evaluation metric is pairwise accuracy: the fraction of held-out pairs where the RM assigns a higher reward to the chosen response. Random chance is 50%; a well-trained RM achieves 70–85% depending on data quality and model size. The mean reward margin (r_w − r_l) measures separability — larger margins indicate more confident, calibrated predictions. Calibration assessment checks whether the RM's win probability σ(r_w − r_l) matches empirical win rates: a RM predicting 80% win rate should be correct 80% of the time. RewardBench is the standard benchmark for comparing RMs across helpfulness, safety, and reasoning axes.

```python
import torch
import numpy as np

def evaluate_reward_model(model, eval_loader, device="cuda"):
    """Compute pairwise accuracy, mean margin, and score distribution statistics."""
    model.eval()
    r_chosen_all, r_rejected_all = [], []
    with torch.no_grad():
        for batch in eval_loader:
            r_w = model(
                input_ids=batch["chosen_input_ids"].to(device),
                attention_mask=batch["chosen_attention_mask"].to(device)
            )
            r_l = model(
                input_ids=batch["rejected_input_ids"].to(device),
                attention_mask=batch["rejected_attention_mask"].to(device)
            )
            r_chosen_all.extend(r_w.cpu().float().tolist())
            r_rejected_all.extend(r_l.cpu().float().tolist())
    rw = np.array(r_chosen_all)
    rl = np.array(r_rejected_all)
    accuracy  = float((rw > rl).mean())
    margin    = float((rw - rl).mean())
    overlap   = float((rw < rl).mean())  # fraction where RM is wrong
    print(f"Pairwise accuracy : {accuracy:.3f}")
    print(f"Mean margin       : {margin:.3f}")
    print(f"Chosen  — mean: {rw.mean():.3f}, std: {rw.std():.3f}")
    print(f"Rejected — mean: {rl.mean():.3f}, std: {rl.std():.3f}")
    print(f"RM error rate     : {overlap:.3f}")
    return {"accuracy": accuracy, "margin": margin}
```

## Reward Hacking Detection

Reward hacking occurs when the policy being trained by RLHF learns to exploit spurious features that the RM has overfit: verbose responses, particular sentence openers, or formatting patterns that correlate with high reward but not genuine quality. Detection requires monitoring the reward score distribution across training iterations — reward hacking manifests as monotonic score inflation without corresponding quality improvement. Ensemble RMs (averaging across 3–5 independently trained RMs) reduce hacking by making it harder to simultaneously exploit all models. KL-divergence regularisation (penalising divergence from the SFT policy) bounds how far the policy can exploit the RM before the KL penalty dominates.

```python
import numpy as np

class RewardHackingMonitor:
    """Track reward distribution across RL training to detect score inflation."""

    def __init__(self, baseline_window=50, detection_window=20, z_threshold=3.0):
        self.history = []  # list of (step, mean, std)
        self.baseline_window  = baseline_window
        self.detection_window = detection_window
        self.z_threshold = z_threshold

    def record(self, step, rewards):
        self.history.append((step, float(np.mean(rewards)), float(np.std(rewards))))

    def detect_inflation(self):
        if len(self.history) < self.baseline_window + self.detection_window:
            return False
        means = [h[1] for h in self.history]
        baseline = np.array(means[:self.baseline_window])
        recent   = np.array(means[-self.detection_window:])
        z = (recent.mean() - baseline.mean()) / (baseline.std() + 1e-8)
        inflating = z > self.z_threshold
        print(f"Baseline mean: {baseline.mean():.3f}  Recent mean: {recent.mean():.3f}  Z={z:.2f}")
        if inflating:
            print(f"[WARNING] Reward inflation detected (Z={z:.2f} > {self.z_threshold}) — possible reward hacking")
        return inflating

# Simulate training with gradual reward inflation
monitor = RewardHackingMonitor(baseline_window=50, detection_window=20)
for step in range(150):
    rewards = np.random.normal(0.5 + step * 0.012, 0.3, size=32)
    monitor.record(step, rewards)
monitor.detect_inflation()
```

## Reward Model Characteristics Comparison

| Model | Size | Training Data | Pairwise Accuracy | Notable Bias / Notes |
| --- | --- | --- | --- | --- |
| InstructGPT RM (OpenAI) | 6B | 50K human comparisons, 2–7 completions/prompt | ~70% held-out | Length bias; human labeller agreement ~72% |
| Anthropic (Claude) RM | 52B | 500K+ HH-RLHF helpfulness + harmlessness pairs | ~75% | Helpfulness-harmlessness trade-off explicitly modelled |
| Llama-3 RM (Meta) | 70B | Proprietary human + synthetic preference pairs | ~80% (Arena) | Length bias reduced via normalisation; strong on reasoning |
| Zephyr RLAIF RM | 7B | AI Feedback — Claude as labeller (UltraFeedback) | ~65% | Less length bias; bounded by LLM judge quality ceiling |
| Nemotron-4-340B-Reward | 340B | Proprietary large-scale synthetic preferences | ~82% (RewardBench) | Near human-agreement; best open published RM as of 2024 |

## DPO, Implicit Rewards, and Bypassing the RM

Direct Preference Optimisation (DPO) bypasses explicit RM training entirely. It shows that the optimal RLHF policy has a closed-form expression in terms of the preference data, allowing direct policy optimisation from pairwise comparisons. The DPO loss is L_DPO = −log σ(β log(π_θ(y_w|x)/π_ref(y_w|x)) − β log(π_θ(y_l|x)/π_ref(y_l|x))), which implicitly defines a reward r(x,y) = β log(π_θ(y|x)/π_ref(y|x)). DPO eliminates RM training overhead and avoids reward hacking (there is no separate RM to hack), but requires the preference data to be high quality since the policy is trained directly on it. Hybrid approaches like IPO and KTO extend DPO to handle label noise and non-pairwise data.

- RLHF pipeline: SFT → RM training on human pairs → PPO optimisation with KL penalty → evaluate with RM.
- DPO shortcut: SFT → DPO directly on preference pairs — no RM, no PPO, half the training stages.
- Best-of-N sampling: generate N responses, re-rank with RM, select the top-scoring one — inference-time reward hacking.
- RM ensemble: train 3–5 RMs on different data splits, average rewards — reduces hacking surface area significantly.
- Length normalisation: divide reward by response length (in tokens) to penalise verbosity bias in the RM signal.
- Reward model calibration: check that σ(r_w - r_l) matches empirical win rate on held-out data via reliability diagrams.

> **Length Bias in Reward Models**: Length bias in reward models is pervasive — RMs trained on human preferences systematically rate longer responses higher even when shorter responses are more accurate. Always check reward vs length correlation and use length-normalised scoring. A simple test: generate two versions of each response (short and verbose) and check if the RM consistently prefers the longer one regardless of content quality.

Reward modelling is the most data-sensitive component of the RLHF pipeline. The RM quality ceiling is set by human labeller agreement (~72–80%), so investing in labeller training, clear annotation guidelines, and careful prompt design pays large dividends. Monitoring reward score distributions throughout RL training (not just at the end) is essential for catching reward hacking before it corrupts the policy. For teams without the budget for large-scale human annotation, RLAIF (using a strong LLM as the preference labeller) or DPO with public preference datasets (UltraFeedback, HH-RLHF) are viable alternatives that approach RM quality within 5–10 percentage points.

---

