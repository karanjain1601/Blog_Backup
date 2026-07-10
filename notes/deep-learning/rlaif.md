---
title: "RLAIF — AI Feedback for Scalable Supervision Without Human Annotators"
slug: "rlaif"
description: "RLAIF (Lee et al., 2023, Google) replaces human preference annotators with a strong teacher LLM to generate preference labels for reward model training, enabling scalable RLHF-equivalent alignment at a fraction of the annotation cost, with debiasing techniques to correct position and verbosity biases in AI judges."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"RLAIF (Reinforcement Learning from AI Feedback, Lee et al. 2023, Google) replaces the human preference labelers in standard RLHF with a strong teacher LLM — such as GPT-4, Claude 3 Opus, or Gemini Ultra — to generate preference labels at scale. The pipeline mirrors RLHF exactly: sample two responses from the policy, prompt the teacher to judge which is preferred and why, use those AI labels to train a reward model (RM), and run PPO with the RM. Lee et al. found that RLAIF-trained models achieve comparable performance to human RLHF models on summarisation benchmarks while reducing annotation cost by orders of magnitude. The key requirement is that the teacher model be substantially better than the policy being trained."},{"type":"heading","level":2,"content":"RLAIF Pipeline"},{"type":"text","content":"The RLAIF pipeline has five stages: (1) Collect prompts from a dataset or user logs. (2) Sample two candidate responses y₁ and y₂ from the current policy for each prompt. (3) Submit the prompt and both responses to the teacher LLM with a structured evaluation prompt asking for a preference judgment and reasoning. (4) Collect the teacher\u0027s label (preferred response) and use it as a training signal to fine-tune the reward model via Bradley-Terry loss. (5) Run PPO with the trained RM to update the policy. The teacher model is called only during RM training, not during PPO; this keeps inference costs bounded even as the policy improves."},{"type":"heading","level":2,"content":"Preference Labeling with Teacher LLM"},{"type":"text","content":"The teacher LLM is prompted with the original user query and both candidate responses, then asked to provide a preference judgment with chain-of-thought reasoning. The reasoning step is important: it forces the judge to articulate why one response is better, reducing noise and enabling post-hoc analysis of the labeling criteria. The teacher\u0027s response is parsed to extract a binary preference label (A or B) which becomes the RM training target. Temperature 0 (greedy decoding) or low temperature (0.1) is used for reproducibility."},{"type":"code","language":"python","content":"import openai\nimport json\nfrom typing import Tuple, Optional\n\ndef rlaif_preference_label(\n    prompt: str,\n    response_a: str,\n    response_b: str,\n    teacher_model: str = \u0027gpt-4o\u0027,\n    criteria: str = \u0027helpful, harmless, and honest\u0027,\n) -\u003e Tuple[str, str, float]:\n    \"\"\"\n    RLAIF: query teacher LLM for preference label between two responses.\n    Returns (preferred: \u0027A\u0027|\u0027B\u0027, reasoning: str, confidence: float).\n    \"\"\"\n    client = openai.OpenAI()\n    system_msg = (\n        \u0027You are an expert evaluator for AI assistant responses. \u0027\n        \u0027Given a user query and two candidate responses, select the better one. \u0027\n        \u0027Respond with valid JSON only.\u0027\n    )\n    user_msg = (\n        f\u0027Evaluate which response is more {criteria}.\\n\\n\u0027\n        f\u0027User query: {prompt}\\n\\n\u0027\n        f\u0027Response A:\\n{response_a}\\n\\n\u0027\n        f\u0027Response B:\\n{response_b}\\n\\n\u0027\n        f\u0027Respond with JSON: {{\u0027\n        f\u0027\"preferred\": \"A\" or \"B\", \u0027\n        f\u0027\"reasoning\": \"brief explanation\", \u0027\n        f\u0027\"confidence\": 0.0 to 1.0}}\u0027\n    )\n    resp = client.chat.completions.create(\n        model=teacher_model,\n        messages=[\n            {\u0027role\u0027: \u0027system\u0027, \u0027content\u0027: system_msg},\n            {\u0027role\u0027: \u0027user\u0027,   \u0027content\u0027: user_msg},\n        ],\n        temperature=0.0,\n        response_format={\u0027type\u0027: \u0027json_object\u0027},\n    ).choices[0].message.content\n    parsed = json.loads(resp)\n    return parsed[\u0027preferred\u0027], parsed[\u0027reasoning\u0027], parsed.get(\u0027confidence\u0027, 1.0)\n\n# Example usage\nresult = rlaif_preference_label(\n    prompt=\u0027Explain what a transformer is.\u0027,\n    response_a=\u0027It is a type of neural network using attention mechanisms.\u0027,\n    response_b=\u0027A transformer is a machine learning model architecture introduced in \u0027\n               \u0027\"Attention is All You Need\" (Vaswani et al. 2017).\u0027,\n    teacher_model=\u0027gpt-4o-mini\u0027,\n)\nprint(f\u0027Preferred: {result[0]}, Confidence: {result[2]:.2f}\u0027)\nprint(f\u0027Reasoning: {result[1]}\u0027)"},{"type":"heading","level":2,"content":"Position Bias Debiasing"},{"type":"text","content":"AI judges exhibit systematic position bias: they tend to prefer whichever response appears first (A) regardless of quality. Verbosity bias is equally common: longer responses are rated higher even when the shorter response is more accurate and concise. These biases, if uncorrected, will train the reward model to prefer long, first-positioned responses and consequently train the policy to generate verbose output. The standard debiasing technique is to query the judge twice — once with order (A, B) and once with order (B, A) — and average or take the majority vote of the two judgments."},{"type":"code","language":"python","content":"import openai\nimport json\nfrom typing import Tuple\n\ndef debiased_preference_label(\n    prompt: str,\n    response_1: str,\n    response_2: str,\n    judge_model: str = \u0027gpt-4o-mini\u0027,\n) -\u003e Tuple[str, float]:\n    \"\"\"\n    Position-bias debiasing: query judge with both orderings and average.\n    Returns (preferred: \u00271\u0027|\u00272\u0027|\u0027tie\u0027, agreement: float).\n    \"\"\"\n    client = openai.OpenAI()\n\n    def judge_pair(first: str, second: str, label_first: str, label_second: str) -\u003e str:\n        msg = (\n            f\u0027Query: {prompt}\\n\\n\u0027\n            f\u0027Response {label_first}:\\n{first}\\n\\n\u0027\n            f\u0027Response {label_second}:\\n{second}\\n\\n\u0027\n            f\u0027Which is better? Respond with JSON: {{\"preferred\": \"{label_first}\" or \"{label_second}\"}}\u0027\n        )\n        resp = client.chat.completions.create(\n            model=judge_model,\n            messages=[{\u0027role\u0027: \u0027user\u0027, \u0027content\u0027: msg}],\n            temperature=0.0,\n            response_format={\u0027type\u0027: \u0027json_object\u0027},\n        ).choices[0].message.content\n        return json.loads(resp)[\u0027preferred\u0027]\n\n    # Forward order: (response_1 as A, response_2 as B)\n    label_forward = judge_pair(response_1, response_2, \u0027A\u0027, \u0027B\u0027)\n    prefers_1_forward = label_forward == \u0027A\u0027\n\n    # Reversed order: (response_2 as A, response_1 as B)\n    label_reverse = judge_pair(response_2, response_1, \u0027A\u0027, \u0027B\u0027)\n    prefers_1_reverse = label_reverse == \u0027B\u0027  # \u0027B\u0027 means response_1 preferred\n\n    # Aggregate\n    if prefers_1_forward and prefers_1_reverse:\n        return \u00271\u0027, 1.0  # both orderings prefer response_1\n    elif not prefers_1_forward and not prefers_1_reverse:\n        return \u00272\u0027, 1.0  # both orderings prefer response_2\n    else:\n        return \u0027tie\u0027, 0.5  # disagreement — position bias detected\n\npreferred, confidence = \u00271\u0027, 1.0  # simulated result\nprint(f\u0027Debiased preference: response {preferred} (confidence={confidence:.2f})\u0027)\nprint(\u0027Tie indicates position bias — discard or use as equal pair in RM training\u0027)"},{"type":"heading","level":2,"content":"AI Judge Quality Evaluation"},{"type":"text","content":"Before deploying an AI judge for RLAIF, its quality should be validated against a calibration set of human-labeled preference pairs. Inter-annotator agreement (Cohen\u0027s κ or Krippendorff\u0027s α) between the AI judge and human annotators quantifies how closely the AI judge tracks human preferences. An AI judge with κ \u003c 0.4 should not be used — its labels introduce too much noise. Additionally, compute per-category agreement to identify domains where the AI judge systematically disagrees with humans (e.g., cultural nuance, humour, technical accuracy in niche fields)."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.metrics import cohen_kappa_score, classification_report\n\ndef evaluate_ai_judge(\n    human_labels: list,\n    ai_labels: list,\n    category_labels: list = None,\n) -\u003e dict:\n    \"\"\"\n    Evaluate AI judge quality vs human labels on a calibration set.\n    Labels should be 0 (prefer A) or 1 (prefer B).\n    \"\"\"\n    human_arr = np.array(human_labels)\n    ai_arr    = np.array(ai_labels)\n\n    kappa     = cohen_kappa_score(human_arr, ai_arr)\n    accuracy  = (human_arr == ai_arr).mean()\n    agreement = np.mean(human_arr == ai_arr)\n\n    results = {\n        \u0027accuracy\u0027:      float(accuracy),\n        \u0027cohen_kappa\u0027:   float(kappa),\n        \u0027agreement_pct\u0027: float(agreement * 100),\n        \u0027quality\u0027:       \u0027good\u0027 if kappa \u003e 0.6 else \u0027marginal\u0027 if kappa \u003e 0.4 else \u0027poor\u0027,\n    }\n    print(f\u0027AI Judge Calibration Report:\u0027)\n    print(f\u0027  Accuracy vs humans: {accuracy:.2%}\u0027)\n    print(f\u0027  Cohen kappa:        {kappa:.3f} ({results[\"quality\"]})\u0027)\n    print(f\u0027  Threshold: kappa \u003e 0.6 = good, 0.4-0.6 = marginal, \u003c0.4 = unusable\u0027)\n    return results\n\nnp.random.seed(42)\nn = 200\nhuman = np.random.randint(0, 2, n).tolist()\n# AI judge agrees 75% of the time with humans\nai = [h if np.random.rand() \u003c 0.75 else 1 - h for h in human]\nmetrics = evaluate_ai_judge(human, ai)"},{"type":"heading","level":2,"content":"RLAIF Reward Model Training"},{"type":"text","content":"After collecting AI-labeled preference pairs, the reward model is trained with the same Bradley-Terry cross-entropy objective used in human RLHF. The only difference is the source of the labels. Comparing RM trained on AI labels versus human labels on a held-out human evaluation set reveals the quality gap between RLAIF and RLHF. Lee et al. found this gap was surprisingly small on summarisation, with RLAIF-trained policies scoring within 2% of RLHF on human preference benchmarks."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nfrom torch.utils.data import DataLoader, TensorDataset\n\nclass SimpleRewardModel(nn.Module):\n    \"\"\"Reward model trained on AI-labeled preference pairs.\"\"\"\n    def __init__(self, input_dim: int = 768, hidden_dim: int = 256):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(input_dim, hidden_dim), nn.ReLU(),\n            nn.Linear(hidden_dim, hidden_dim), nn.ReLU(),\n            nn.Linear(hidden_dim, 1),\n        )\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        return self.net(x).squeeze(-1)\n\ndef train_rm_on_ai_labels(n_pairs: int = 1000, epochs: int = 3):\n    \"\"\"Train RM on AI-labeled preference pairs; compare vs human-label accuracy.\"\"\"\n    torch.manual_seed(0)\n    model = SimpleRewardModel(input_dim=128)\n    optim = torch.optim.Adam(model.parameters(), lr=1e-3)\n    # Simulate feature vectors for chosen vs rejected responses\n    chosen_feats   = torch.randn(n_pairs, 128) + 0.5\n    rejected_feats = torch.randn(n_pairs, 128) - 0.5\n    dataset = TensorDataset(chosen_feats, rejected_feats)\n    loader  = DataLoader(dataset, batch_size=64, shuffle=True)\n    for epoch in range(epochs):\n        total_loss, correct = 0.0, 0\n        for chosen, rejected in loader:\n            r_c = model(chosen)\n            r_r = model(rejected)\n            loss = -F.logsigmoid(r_c - r_r).mean()  # Bradley-Terry\n            optim.zero_grad(); loss.backward(); optim.step()\n            total_loss += loss.item() * len(chosen)\n            correct    += (r_c \u003e r_r).sum().item()\n        acc = correct / n_pairs\n        print(f\u0027Epoch {epoch+1}: loss={total_loss/n_pairs:.4f}, pref_acc={acc:.2%}\u0027)\n    return model\n\ntrained_rm = train_rm_on_ai_labels()"},{"type":"heading","level":2,"content":"RLAIF Variants Comparison"},{"type":"table","headers":["Variant","Teacher Model","Bias Mitigation","Human Involvement","Cost","Quality"],"rows":[["Standard RLHF","N/A — human annotators","None — humans have their own biases","High — pairwise comparisons","Very High","Gold standard; captures subjective nuance"],["Standard RLAIF","GPT-4 / Claude Opus","None — raw AI labels","Low — prompt design only","Medium","Good; small quality gap vs RLHF on summarisation"],["Debiased RLAIF","GPT-4 / Claude Opus","Order swap + averaging","Low","Medium+ (2x judge calls)","Better than standard RLAIF; reduces systematic bias"],["Constitutional RLAIF","GPT-4 with principles","Principle-based evaluation","Low — principle writing","Medium","Strong; consistent with explicit values"],["Self-RLAIF","Policy itself (weaker judge)","None","None","Low","Weak — circular; useful only for initial data augmentation"],["Direct RLAIF","Teacher score on single response","Calibration set validation","Low","Low","Experimental; avoids pairwise format entirely"]]},{"type":"heading","level":2,"content":"Biases and Mitigation Strategies"},{"type":"text","content":"AI judges exhibit three primary systematic biases. Position bias: the judge prefers whichever response appears first in the prompt. Verbosity bias: longer responses are rated higher independent of quality, which trains the policy to generate unnecessarily long outputs. Sycophancy: if the judge\u0027s own responses are used as one of the candidates (self-RLAIF), it will systematically prefer its own style. Mitigation strategies include: double-query with order swapping (eliminates position bias), length-penalised evaluation prompts (reduces verbosity bias), and calibration against human labels before deployment (detects systematic errors)."},{"type":"callout","variant":"warning","title":"AI Judge Systematic Biases","content":"AI judges show systematic verbosity and position bias — always debias by (1) averaging labels from both orderings and (2) penalizing judges for length-correlated preferences to prevent training the policy to produce verbose low-quality responses. An undebiased RLAIF pipeline will reliably train the policy to output longer and longer responses over successive RL iterations even when shorter responses would be more helpful."},{"type":"list","ordered":false,"items":["The teacher judge must be substantially stronger than the policy — using the policy itself as its own judge produces degenerate labels.","Always validate AI judge quality on a calibration set with human labels before using it for RM training (target Cohen κ \u003e 0.6).","Double-query with order swapping eliminates position bias at the cost of 2x teacher API calls.","Length-normalise judge prompts: explicitly instruct the judge to prefer concise correct answers over verbose ones.","RLAIF is most effective for domains where AI judges are reliable: coding, factual QA, structured tasks. Avoid for subjective creative tasks.","Combine RLAIF (broad coverage, low cost) with human RLHF (high quality, targeted) for best results at scale."]},{"type":"divider"}]"
---
# RLAIF — AI Feedback for Scalable Supervision Without Human Annotators

RLAIF (Reinforcement Learning from AI Feedback, Lee et al. 2023, Google) replaces the human preference labelers in standard RLHF with a strong teacher LLM — such as GPT-4, Claude 3 Opus, or Gemini Ultra — to generate preference labels at scale. The pipeline mirrors RLHF exactly: sample two responses from the policy, prompt the teacher to judge which is preferred and why, use those AI labels to train a reward model (RM), and run PPO with the RM. Lee et al. found that RLAIF-trained models achieve comparable performance to human RLHF models on summarisation benchmarks while reducing annotation cost by orders of magnitude. The key requirement is that the teacher model be substantially better than the policy being trained.

## RLAIF Pipeline

The RLAIF pipeline has five stages: (1) Collect prompts from a dataset or user logs. (2) Sample two candidate responses y₁ and y₂ from the current policy for each prompt. (3) Submit the prompt and both responses to the teacher LLM with a structured evaluation prompt asking for a preference judgment and reasoning. (4) Collect the teacher's label (preferred response) and use it as a training signal to fine-tune the reward model via Bradley-Terry loss. (5) Run PPO with the trained RM to update the policy. The teacher model is called only during RM training, not during PPO; this keeps inference costs bounded even as the policy improves.

## Preference Labeling with Teacher LLM

The teacher LLM is prompted with the original user query and both candidate responses, then asked to provide a preference judgment with chain-of-thought reasoning. The reasoning step is important: it forces the judge to articulate why one response is better, reducing noise and enabling post-hoc analysis of the labeling criteria. The teacher's response is parsed to extract a binary preference label (A or B) which becomes the RM training target. Temperature 0 (greedy decoding) or low temperature (0.1) is used for reproducibility.

```python
import openai
import json
from typing import Tuple, Optional

def rlaif_preference_label(
    prompt: str,
    response_a: str,
    response_b: str,
    teacher_model: str = 'gpt-4o',
    criteria: str = 'helpful, harmless, and honest',
) -> Tuple[str, str, float]:
    """
    RLAIF: query teacher LLM for preference label between two responses.
    Returns (preferred: 'A'|'B', reasoning: str, confidence: float).
    """
    client = openai.OpenAI()
    system_msg = (
        'You are an expert evaluator for AI assistant responses. '
        'Given a user query and two candidate responses, select the better one. '
        'Respond with valid JSON only.'
    )
    user_msg = (
        f'Evaluate which response is more {criteria}.\n\n'
        f'User query: {prompt}\n\n'
        f'Response A:\n{response_a}\n\n'
        f'Response B:\n{response_b}\n\n'
        f'Respond with JSON: {{'
        f'"preferred": "A" or "B", '
        f'"reasoning": "brief explanation", '
        f'"confidence": 0.0 to 1.0}}'
    )
    resp = client.chat.completions.create(
        model=teacher_model,
        messages=[
            {'role': 'system', 'content': system_msg},
            {'role': 'user',   'content': user_msg},
        ],
        temperature=0.0,
        response_format={'type': 'json_object'},
    ).choices[0].message.content
    parsed = json.loads(resp)
    return parsed['preferred'], parsed['reasoning'], parsed.get('confidence', 1.0)

# Example usage
result = rlaif_preference_label(
    prompt='Explain what a transformer is.',
    response_a='It is a type of neural network using attention mechanisms.',
    response_b='A transformer is a machine learning model architecture introduced in '
               '"Attention is All You Need" (Vaswani et al. 2017).',
    teacher_model='gpt-4o-mini',
)
print(f'Preferred: {result[0]}, Confidence: {result[2]:.2f}')
print(f'Reasoning: {result[1]}')
```

## Position Bias Debiasing

AI judges exhibit systematic position bias: they tend to prefer whichever response appears first (A) regardless of quality. Verbosity bias is equally common: longer responses are rated higher even when the shorter response is more accurate and concise. These biases, if uncorrected, will train the reward model to prefer long, first-positioned responses and consequently train the policy to generate verbose output. The standard debiasing technique is to query the judge twice — once with order (A, B) and once with order (B, A) — and average or take the majority vote of the two judgments.

```python
import openai
import json
from typing import Tuple

def debiased_preference_label(
    prompt: str,
    response_1: str,
    response_2: str,
    judge_model: str = 'gpt-4o-mini',
) -> Tuple[str, float]:
    """
    Position-bias debiasing: query judge with both orderings and average.
    Returns (preferred: '1'|'2'|'tie', agreement: float).
    """
    client = openai.OpenAI()

    def judge_pair(first: str, second: str, label_first: str, label_second: str) -> str:
        msg = (
            f'Query: {prompt}\n\n'
            f'Response {label_first}:\n{first}\n\n'
            f'Response {label_second}:\n{second}\n\n'
            f'Which is better? Respond with JSON: {{"preferred": "{label_first}" or "{label_second}"}}'
        )
        resp = client.chat.completions.create(
            model=judge_model,
            messages=[{'role': 'user', 'content': msg}],
            temperature=0.0,
            response_format={'type': 'json_object'},
        ).choices[0].message.content
        return json.loads(resp)['preferred']

    # Forward order: (response_1 as A, response_2 as B)
    label_forward = judge_pair(response_1, response_2, 'A', 'B')
    prefers_1_forward = label_forward == 'A'

    # Reversed order: (response_2 as A, response_1 as B)
    label_reverse = judge_pair(response_2, response_1, 'A', 'B')
    prefers_1_reverse = label_reverse == 'B'  # 'B' means response_1 preferred

    # Aggregate
    if prefers_1_forward and prefers_1_reverse:
        return '1', 1.0  # both orderings prefer response_1
    elif not prefers_1_forward and not prefers_1_reverse:
        return '2', 1.0  # both orderings prefer response_2
    else:
        return 'tie', 0.5  # disagreement — position bias detected

preferred, confidence = '1', 1.0  # simulated result
print(f'Debiased preference: response {preferred} (confidence={confidence:.2f})')
print('Tie indicates position bias — discard or use as equal pair in RM training')
```

## AI Judge Quality Evaluation

Before deploying an AI judge for RLAIF, its quality should be validated against a calibration set of human-labeled preference pairs. Inter-annotator agreement (Cohen's κ or Krippendorff's α) between the AI judge and human annotators quantifies how closely the AI judge tracks human preferences. An AI judge with κ < 0.4 should not be used — its labels introduce too much noise. Additionally, compute per-category agreement to identify domains where the AI judge systematically disagrees with humans (e.g., cultural nuance, humour, technical accuracy in niche fields).

```python
import numpy as np
from sklearn.metrics import cohen_kappa_score, classification_report

def evaluate_ai_judge(
    human_labels: list,
    ai_labels: list,
    category_labels: list = None,
) -> dict:
    """
    Evaluate AI judge quality vs human labels on a calibration set.
    Labels should be 0 (prefer A) or 1 (prefer B).
    """
    human_arr = np.array(human_labels)
    ai_arr    = np.array(ai_labels)

    kappa     = cohen_kappa_score(human_arr, ai_arr)
    accuracy  = (human_arr == ai_arr).mean()
    agreement = np.mean(human_arr == ai_arr)

    results = {
        'accuracy':      float(accuracy),
        'cohen_kappa':   float(kappa),
        'agreement_pct': float(agreement * 100),
        'quality':       'good' if kappa > 0.6 else 'marginal' if kappa > 0.4 else 'poor',
    }
    print(f'AI Judge Calibration Report:')
    print(f'  Accuracy vs humans: {accuracy:.2%}')
    print(f'  Cohen kappa:        {kappa:.3f} ({results["quality"]})')
    print(f'  Threshold: kappa > 0.6 = good, 0.4-0.6 = marginal, <0.4 = unusable')
    return results

np.random.seed(42)
n = 200
human = np.random.randint(0, 2, n).tolist()
# AI judge agrees 75% of the time with humans
ai = [h if np.random.rand() < 0.75 else 1 - h for h in human]
metrics = evaluate_ai_judge(human, ai)
```

## RLAIF Reward Model Training

After collecting AI-labeled preference pairs, the reward model is trained with the same Bradley-Terry cross-entropy objective used in human RLHF. The only difference is the source of the labels. Comparing RM trained on AI labels versus human labels on a held-out human evaluation set reveals the quality gap between RLAIF and RLHF. Lee et al. found this gap was surprisingly small on summarisation, with RLAIF-trained policies scoring within 2% of RLHF on human preference benchmarks.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
from torch.utils.data import DataLoader, TensorDataset

class SimpleRewardModel(nn.Module):
    """Reward model trained on AI-labeled preference pairs."""
    def __init__(self, input_dim: int = 768, hidden_dim: int = 256):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(input_dim, hidden_dim), nn.ReLU(),
            nn.Linear(hidden_dim, hidden_dim), nn.ReLU(),
            nn.Linear(hidden_dim, 1),
        )

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return self.net(x).squeeze(-1)

def train_rm_on_ai_labels(n_pairs: int = 1000, epochs: int = 3):
    """Train RM on AI-labeled preference pairs; compare vs human-label accuracy."""
    torch.manual_seed(0)
    model = SimpleRewardModel(input_dim=128)
    optim = torch.optim.Adam(model.parameters(), lr=1e-3)
    # Simulate feature vectors for chosen vs rejected responses
    chosen_feats   = torch.randn(n_pairs, 128) + 0.5
    rejected_feats = torch.randn(n_pairs, 128) - 0.5
    dataset = TensorDataset(chosen_feats, rejected_feats)
    loader  = DataLoader(dataset, batch_size=64, shuffle=True)
    for epoch in range(epochs):
        total_loss, correct = 0.0, 0
        for chosen, rejected in loader:
            r_c = model(chosen)
            r_r = model(rejected)
            loss = -F.logsigmoid(r_c - r_r).mean()  # Bradley-Terry
            optim.zero_grad(); loss.backward(); optim.step()
            total_loss += loss.item() * len(chosen)
            correct    += (r_c > r_r).sum().item()
        acc = correct / n_pairs
        print(f'Epoch {epoch+1}: loss={total_loss/n_pairs:.4f}, pref_acc={acc:.2%}')
    return model

trained_rm = train_rm_on_ai_labels()
```

## RLAIF Variants Comparison

| Variant | Teacher Model | Bias Mitigation | Human Involvement | Cost | Quality |
| --- | --- | --- | --- | --- | --- |
| Standard RLHF | N/A — human annotators | None — humans have their own biases | High — pairwise comparisons | Very High | Gold standard; captures subjective nuance |
| Standard RLAIF | GPT-4 / Claude Opus | None — raw AI labels | Low — prompt design only | Medium | Good; small quality gap vs RLHF on summarisation |
| Debiased RLAIF | GPT-4 / Claude Opus | Order swap + averaging | Low | Medium+ (2x judge calls) | Better than standard RLAIF; reduces systematic bias |
| Constitutional RLAIF | GPT-4 with principles | Principle-based evaluation | Low — principle writing | Medium | Strong; consistent with explicit values |
| Self-RLAIF | Policy itself (weaker judge) | None | None | Low | Weak — circular; useful only for initial data augmentation |
| Direct RLAIF | Teacher score on single response | Calibration set validation | Low | Low | Experimental; avoids pairwise format entirely |

## Biases and Mitigation Strategies

AI judges exhibit three primary systematic biases. Position bias: the judge prefers whichever response appears first in the prompt. Verbosity bias: longer responses are rated higher independent of quality, which trains the policy to generate unnecessarily long outputs. Sycophancy: if the judge's own responses are used as one of the candidates (self-RLAIF), it will systematically prefer its own style. Mitigation strategies include: double-query with order swapping (eliminates position bias), length-penalised evaluation prompts (reduces verbosity bias), and calibration against human labels before deployment (detects systematic errors).

> **AI Judge Systematic Biases**: AI judges show systematic verbosity and position bias — always debias by (1) averaging labels from both orderings and (2) penalizing judges for length-correlated preferences to prevent training the policy to produce verbose low-quality responses. An undebiased RLAIF pipeline will reliably train the policy to output longer and longer responses over successive RL iterations even when shorter responses would be more helpful.

- The teacher judge must be substantially stronger than the policy — using the policy itself as its own judge produces degenerate labels.
- Always validate AI judge quality on a calibration set with human labels before using it for RM training (target Cohen κ > 0.6).
- Double-query with order swapping eliminates position bias at the cost of 2x teacher API calls.
- Length-normalise judge prompts: explicitly instruct the judge to prefer concise correct answers over verbose ones.
- RLAIF is most effective for domains where AI judges are reliable: coding, factual QA, structured tasks. Avoid for subjective creative tasks.
- Combine RLAIF (broad coverage, low cost) with human RLHF (high quality, targeted) for best results at scale.

---

