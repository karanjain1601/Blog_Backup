---
title: "Constitutional AI — Principle-Based Self-Critique and Red-Team-Free Alignment"
slug: "constitutional-ai"
description: "Constitutional AI (Bai et al., 2022, Anthropic) aligns LLMs using a set of written principles rather than extensive human red-teaming, combining supervised learning from AI-generated critiques and revisions (SL-CAI) with RLHF from AI-generated preference labels (RL-CAI / RLAIF) to resolve the harmless-helpful tradeoff."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Constitutional AI (CAI, Bai et al. 2022, Anthropic) is an alignment technique that uses a written set of principles — the constitution — to guide both supervised fine-tuning and reinforcement learning, replacing the labour-intensive human red-teaming loop with AI-driven critique and revision. The method has two stages: SL-CAI (supervised learning from AI feedback), where the model critiques and revises its own harmful responses according to principles, and RL-CAI (also called RLAIF), where a reward model is trained on AI-generated preference labels rather than human labels. CAI resolves the classic harmless-helpful tradeoff: standard RLHF safety training often makes models unhelpfully cautious, while CAI allows a model to be both harmless and genuinely helpful."},{"type":"heading","level":2,"content":"CAI Architecture: SL-CAI and RL-CAI"},{"type":"text","content":"The SL-CAI stage follows a four-step loop: (1) collect harmful or adversarial prompts, (2) generate an initial (potentially harmful) response, (3) apply a critique prompt asking the model to identify how the response violates a specific principle, (4) generate a revised response that addresses the critique. This critique-revise loop can be applied 2–3 times per example. The final revised responses are used to fine-tune the model. The RL-CAI stage then trains a reward model (RM) using AI-generated preference labels — a judge LLM is shown two responses and asked which better follows a given principle, producing preference pairs without human annotators."},{"type":"heading","level":2,"content":"Critique-Revise Pipeline (SL-CAI)"},{"type":"text","content":"The critique-revise pipeline is the core of SL-CAI. For each harmful prompt, the model first generates an unrestricted response (before safety training). A critique prompt is then prepended asking the model to identify harmful elements according to a specific constitutional principle. Finally, a revision prompt asks the model to rewrite the response to remove the identified harms. This process is repeated 2–3 times, with each revision becoming the input to the next critique step. The final revised response is added to the fine-tuning dataset alongside the original prompt."},{"type":"code","language":"python","content":"import openai\n\ndef critique_revise_pipeline(\n    prompt: str,\n    principle: str,\n    model: str = \u0027gpt-4o\u0027,\n    n_rounds: int = 2,\n) -\u003e dict:\n    \"\"\"\n    SL-CAI critique-revise loop.\n    1. Generate initial response to potentially harmful prompt.\n    2. Critique the response against a constitutional principle.\n    3. Generate revised response removing identified harms.\n    Repeat n_rounds times; return initial + final revised response.\n    \"\"\"\n    client = openai.OpenAI()\n\n    # Step 1: generate initial (unconstrained) response\n    initial = client.chat.completions.create(\n        model=model,\n        messages=[{\u0027role\u0027: \u0027user\u0027, \u0027content\u0027: prompt}]\n    ).choices[0].message.content\n\n    current = initial\n    history = []\n    for round_idx in range(n_rounds):\n        # Step 2: critique\n        critique_prompt = (\n            f\u0027Identify specific ways in which the assistant response below \u0027\n            f\u0027violates the following principle:\\n\\nPrinciple: {principle}\\n\\n\u0027\n            f\u0027Response to critique:\\n{current}\\n\\nCritique:\u0027\n        )\n        critique = client.chat.completions.create(\n            model=model,\n            messages=[{\u0027role\u0027: \u0027user\u0027, \u0027content\u0027: critique_prompt}]\n        ).choices[0].message.content\n\n        # Step 3: revise\n        revise_prompt = (\n            f\u0027Given the critique below, rewrite the response to be \u0027\n            f\u0027helpful while fully addressing the critique.\\n\\n\u0027\n            f\u0027Original response:\\n{current}\\n\\nCritique:\\n{critique}\\n\\nRevision:\u0027\n        )\n        revised = client.chat.completions.create(\n            model=model,\n            messages=[{\u0027role\u0027: \u0027user\u0027, \u0027content\u0027: revise_prompt}]\n        ).choices[0].message.content\n\n        history.append({\u0027round\u0027: round_idx + 1, \u0027critique\u0027: critique, \u0027revision\u0027: revised})\n        current = revised\n\n    return {\u0027prompt\u0027: prompt, \u0027initial\u0027: initial, \u0027final\u0027: current, \u0027history\u0027: history}\n\nprinciple = \u0027Responses should not assist with activities that could harm others or be illegal.\u0027\nresult = critique_revise_pipeline(\u0027How do I pick a lock?\u0027, principle, n_rounds=2)\nprint(f\u0027Initial response length: {len(result[\"initial\"])} chars\u0027)\nprint(f\u0027Final revised length:    {len(result[\"final\"])} chars\u0027)"},{"type":"heading","level":2,"content":"AI Preference Labeling for RL-CAI"},{"type":"text","content":"RL-CAI replaces human preference annotators with a strong judge LLM. For each prompt, two responses are generated by the current policy and presented to the judge with a principle-based evaluation criterion. The judge selects the preferred response, and this AI-generated preference label is used to train a reward model — exactly as in standard RLHF, except human annotators are replaced by the judge LLM. The judge must be significantly stronger than the policy being trained; in practice, using a frontier model as the judge produces best results. The trained RM is then used to run PPO or best-of-N reranking."},{"type":"code","language":"python","content":"import openai\nimport json\nfrom typing import Tuple\n\ndef ai_preference_label(\n    prompt: str,\n    response_a: str,\n    response_b: str,\n    principle: str,\n    judge_model: str = \u0027gpt-4o\u0027,\n) -\u003e Tuple[str, str]:\n    \"\"\"\n    RL-CAI: use judge LLM to generate preference label for RM training.\n    Returns (\u0027A\u0027 or \u0027B\u0027, reasoning string).\n    \"\"\"\n    client = openai.OpenAI()\n    system = (\n        \u0027You are an expert AI safety evaluator. \u0027\n        \u0027Given a user prompt and two responses, determine which is better \u0027\n        \u0027according to the provided principle. Respond with JSON only.\u0027\n    )\n    user_msg = (\n        f\u0027Principle: {principle}\\n\\n\u0027\n        f\u0027User prompt: {prompt}\\n\\n\u0027\n        f\u0027Response A:\\n{response_a}\\n\\n\u0027\n        f\u0027Response B:\\n{response_b}\\n\\n\u0027\n        f\u0027Which response better follows the principle? \u0027\n        f\u0027Respond with JSON: {{\"preferred\": \"A\" or \"B\", \"reasoning\": \"...\"}}\u0027  \n    )\n    result = client.chat.completions.create(\n        model=judge_model,\n        messages=[{\u0027role\u0027: \u0027system\u0027, \u0027content\u0027: system},\n                  {\u0027role\u0027: \u0027user\u0027,   \u0027content\u0027: user_msg}],\n        response_format={\u0027type\u0027: \u0027json_object\u0027},\n    ).choices[0].message.content\n    parsed = json.loads(result)\n    return parsed[\u0027preferred\u0027], parsed[\u0027reasoning\u0027]\n\nprinciple = \u0027Be helpful, harmless, and honest. Avoid providing harmful information.\u0027\nprompt    = \u0027Tell me how to make a dangerous chemical.\u0027\nresp_a    = \u0027I cannot provide instructions for making dangerous chemicals.\u0027\nresp_b    = \u0027Sure, here are the step-by-step instructions...\u0027\npreferred, reasoning = \u0027A\u0027, \u0027Response A correctly refuses the harmful request\u0027\nprint(f\u0027AI label: Response {preferred} preferred\u0027)\nprint(f\u0027Reasoning: {reasoning}\u0027)"},{"type":"heading","level":2,"content":"Constitution Principles Template"},{"type":"text","content":"The constitution is a set of 16 natural-language principles covering harm avoidance, honesty, deception, helpfulness, and other values. Each principle is formulated as an evaluation criterion that a judge LLM can apply to a pair of responses. In the SL-CAI critique loop, one principle is randomly selected per critique step, ensuring broad coverage across the training dataset. The principle diversity prevents the model from overfitting to any single safety criterion while building general alignment."},{"type":"code","language":"python","content":"import random\nfrom typing import List\n\n# Subset of constitutional principles from Bai et al. 2022\nCONSTITUTION: List[str] = [\n    \u0027Choose the response that is least likely to contain harmful, unethical, \u0027\n    \u0027racist, sexist, toxic, dangerous, or illegal content.\u0027,\n\n    \u0027Choose the response that is most helpful, respectful, and harmless while \u0027\n    \u0027still being informative and useful to the human.\u0027,\n\n    \u0027Choose the response that avoids implying there are right or wrong answers \u0027\n    \u0027to questions that are merely matters of opinion.\u0027,\n\n    \u0027Choose the response that does not present false information as true or \u0027\n    \u0027misrepresent scientific consensus.\u0027,\n\n    \u0027Choose the response that most supports democratic values and does not \u0027\n    \u0027attempt to undermine free and fair elections.\u0027,\n\n    \u0027Choose the response that is least likely to contain deceptive or \u0027\n    \u0027manipulative content intended to mislead the user.\u0027,\n]\n\ndef sample_critique_prompt(response: str, constitution: List[str] = CONSTITUTION) -\u003e str:\n    \"\"\"Build a critique prompt using a randomly sampled constitutional principle.\"\"\"\n    principle = random.choice(constitution)\n    return (\n        f\u0027Identify specific ways in which the following response is harmful, \u0027\n        f\u0027unethical, or problematic according to this principle:\\n\\n\u0027\n        f\u0027Principle: {principle}\\n\\n\u0027\n        f\u0027Response: {response}\\n\\n\u0027\n        f\u0027Critique:\u0027\n    )\n\nrandom.seed(42)\nexample_response = \u0027You should definitely vote for Candidate X — they are the only good choice.\u0027\nprint(sample_critique_prompt(example_response))"},{"type":"heading","level":2,"content":"RL-CAI Reward Model Training"},{"type":"text","content":"The RL-CAI reward model is trained identically to a standard RLHF reward model, but the preference labels come from the judge LLM rather than human annotators. A batch of prompt-response pairs is collected from the current policy, each pair is scored by the judge using a constitutional principle, and the resulting preference labels form the training signal. The RM is fine-tuned with a Bradley-Terry cross-entropy loss over the preference pairs. Once trained, the RM can be used for PPO training or best-of-N reranking."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nfrom transformers import AutoModel, AutoTokenizer\n\nclass RewardModel(nn.Module):\n    \"\"\"Reward model for RL-CAI: fine-tuned LM with scalar reward head.\"\"\"\n    def __init__(self, base_model_name: str = \u0027gpt2\u0027):\n        super().__init__()\n        self.lm = AutoModel.from_pretrained(base_model_name)\n        hidden = self.lm.config.hidden_size\n        self.reward_head = nn.Linear(hidden, 1, bias=False)\n\n    def forward(self, input_ids, attention_mask):\n        out = self.lm(input_ids=input_ids, attention_mask=attention_mask)\n        # Use last non-padding token representation as reward\n        last_idx = attention_mask.sum(dim=1) - 1\n        last_hidden = out.last_hidden_state[torch.arange(input_ids.size(0)), last_idx]\n        return self.reward_head(last_hidden).squeeze(-1)  # (B,)\n\ndef bradley_terry_loss(reward_chosen, reward_rejected):\n    \"\"\"Preference learning loss: chosen response should have higher reward.\"\"\"\n    return -F.logsigmoid(reward_chosen - reward_rejected).mean()\n\n# Simulate RM training step on AI-labeled preference pairs\ntorch.manual_seed(0)\nreward_chosen   = torch.randn(8) + 0.5   # AI judge prefers these\nreward_rejected = torch.randn(8) - 0.5   # AI judge rejects these\nloss = bradley_terry_loss(reward_chosen, reward_rejected)\nprint(f\u0027Bradley-Terry loss: {loss.item():.4f}\u0027)\nacc = (reward_chosen \u003e reward_rejected).float().mean()\nprint(f\u0027Preference accuracy: {acc.item():.2%}\u0027)"},{"type":"heading","level":2,"content":"CAI vs Standard RLHF"},{"type":"table","headers":["Aspect","Standard RLHF","Constitutional AI (CAI)","Key Implication"],"rows":[["Preference data source","Human annotators","Judge LLM using principles","CAI scales without human bottleneck"],["Human involvement","High — pairwise comparisons","Low — principle writing only","CAI requires ~50 hours vs thousands"],["Red-teaming","Extensive manual red-teaming","Automated via harmful prompt sampling","CAI covers more edge cases automatically"],["Harmless-helpful tradeoff","Safety often hurts helpfulness","Both improved simultaneously via critique","CAI resolves the tradeoff explicitly"],["Consistency","Varies across annotators","Consistent — principle applied uniformly","CAI reduces label noise significantly"],["Scalability","Limited by annotator capacity","Scales with compute, not headcount","CAI enables continuous alignment updates"],["Key application","Initial RLHF alignment","Claude\u0027s core alignment method","CAI underpins all Claude model versions"]]},{"type":"heading","level":2,"content":"Harmless-Helpful Tradeoff"},{"type":"text","content":"The harmless-helpful tradeoff is a well-documented failure mode of standard RLHF safety training: as a model is trained to be less harmful, it tends to refuse more requests — including legitimate ones — leading to reduced helpfulness. Constitutional AI resolves this by using critique-revise to teach the model how to be helpful even on borderline requests, rather than simply refusing them. The revised responses demonstrate that helpful and safe responses can coexist, fine-tuning the model\u0027s refusal threshold to be more accurately calibrated. Empirically, CAI-trained models show improvements on both harmlessness and helpfulness metrics simultaneously."},{"type":"callout","variant":"tip","title":"Optimal Critique-Revise Rounds","content":"The critique-revise loop in Constitutional AI works best with 2–3 revision rounds — more rounds show diminishing returns and risk over-correcting helpful responses into over-cautious refusals. After 3 rounds, the revised responses tend to become excessively hedged and less informative. Two rounds is typically the sweet spot: the first revision removes the core harm, the second refines the tone and helpfulness."},{"type":"list","ordered":false,"items":["The constitution has 16 principles covering harm, honesty, deception, helpfulness, democratic values, and cultural sensitivity.","SL-CAI fine-tuning teaches the model what good responses look like before RL-CAI pushes it further via reward maximisation.","The judge LLM in RL-CAI must be stronger than the policy being trained — using the policy itself as judge produces degenerate labels.","CAI was extended in 2025 to Constitutional Classifiers: input/output filters that block policy-violating content at inference time.","The critique-revise data augmentation alone (without RL) substantially improves harmlessness on red-team benchmarks.","Principle diversity during critique sampling is essential — always randomise which principle is applied per training example."]},{"type":"divider"}]"
---
# Constitutional AI — Principle-Based Self-Critique and Red-Team-Free Alignment

Constitutional AI (CAI, Bai et al. 2022, Anthropic) is an alignment technique that uses a written set of principles — the constitution — to guide both supervised fine-tuning and reinforcement learning, replacing the labour-intensive human red-teaming loop with AI-driven critique and revision. The method has two stages: SL-CAI (supervised learning from AI feedback), where the model critiques and revises its own harmful responses according to principles, and RL-CAI (also called RLAIF), where a reward model is trained on AI-generated preference labels rather than human labels. CAI resolves the classic harmless-helpful tradeoff: standard RLHF safety training often makes models unhelpfully cautious, while CAI allows a model to be both harmless and genuinely helpful.

## CAI Architecture: SL-CAI and RL-CAI

The SL-CAI stage follows a four-step loop: (1) collect harmful or adversarial prompts, (2) generate an initial (potentially harmful) response, (3) apply a critique prompt asking the model to identify how the response violates a specific principle, (4) generate a revised response that addresses the critique. This critique-revise loop can be applied 2–3 times per example. The final revised responses are used to fine-tune the model. The RL-CAI stage then trains a reward model (RM) using AI-generated preference labels — a judge LLM is shown two responses and asked which better follows a given principle, producing preference pairs without human annotators.

## Critique-Revise Pipeline (SL-CAI)

The critique-revise pipeline is the core of SL-CAI. For each harmful prompt, the model first generates an unrestricted response (before safety training). A critique prompt is then prepended asking the model to identify harmful elements according to a specific constitutional principle. Finally, a revision prompt asks the model to rewrite the response to remove the identified harms. This process is repeated 2–3 times, with each revision becoming the input to the next critique step. The final revised response is added to the fine-tuning dataset alongside the original prompt.

```python
import openai

def critique_revise_pipeline(
    prompt: str,
    principle: str,
    model: str = 'gpt-4o',
    n_rounds: int = 2,
) -> dict:
    """
    SL-CAI critique-revise loop.
    1. Generate initial response to potentially harmful prompt.
    2. Critique the response against a constitutional principle.
    3. Generate revised response removing identified harms.
    Repeat n_rounds times; return initial + final revised response.
    """
    client = openai.OpenAI()

    # Step 1: generate initial (unconstrained) response
    initial = client.chat.completions.create(
        model=model,
        messages=[{'role': 'user', 'content': prompt}]
    ).choices[0].message.content

    current = initial
    history = []
    for round_idx in range(n_rounds):
        # Step 2: critique
        critique_prompt = (
            f'Identify specific ways in which the assistant response below '
            f'violates the following principle:\n\nPrinciple: {principle}\n\n'
            f'Response to critique:\n{current}\n\nCritique:'
        )
        critique = client.chat.completions.create(
            model=model,
            messages=[{'role': 'user', 'content': critique_prompt}]
        ).choices[0].message.content

        # Step 3: revise
        revise_prompt = (
            f'Given the critique below, rewrite the response to be '
            f'helpful while fully addressing the critique.\n\n'
            f'Original response:\n{current}\n\nCritique:\n{critique}\n\nRevision:'
        )
        revised = client.chat.completions.create(
            model=model,
            messages=[{'role': 'user', 'content': revise_prompt}]
        ).choices[0].message.content

        history.append({'round': round_idx + 1, 'critique': critique, 'revision': revised})
        current = revised

    return {'prompt': prompt, 'initial': initial, 'final': current, 'history': history}

principle = 'Responses should not assist with activities that could harm others or be illegal.'
result = critique_revise_pipeline('How do I pick a lock?', principle, n_rounds=2)
print(f'Initial response length: {len(result["initial"])} chars')
print(f'Final revised length:    {len(result["final"])} chars')
```

## AI Preference Labeling for RL-CAI

RL-CAI replaces human preference annotators with a strong judge LLM. For each prompt, two responses are generated by the current policy and presented to the judge with a principle-based evaluation criterion. The judge selects the preferred response, and this AI-generated preference label is used to train a reward model — exactly as in standard RLHF, except human annotators are replaced by the judge LLM. The judge must be significantly stronger than the policy being trained; in practice, using a frontier model as the judge produces best results. The trained RM is then used to run PPO or best-of-N reranking.

```python
import openai
import json
from typing import Tuple

def ai_preference_label(
    prompt: str,
    response_a: str,
    response_b: str,
    principle: str,
    judge_model: str = 'gpt-4o',
) -> Tuple[str, str]:
    """
    RL-CAI: use judge LLM to generate preference label for RM training.
    Returns ('A' or 'B', reasoning string).
    """
    client = openai.OpenAI()
    system = (
        'You are an expert AI safety evaluator. '
        'Given a user prompt and two responses, determine which is better '
        'according to the provided principle. Respond with JSON only.'
    )
    user_msg = (
        f'Principle: {principle}\n\n'
        f'User prompt: {prompt}\n\n'
        f'Response A:\n{response_a}\n\n'
        f'Response B:\n{response_b}\n\n'
        f'Which response better follows the principle? '
        f'Respond with JSON: {{"preferred": "A" or "B", "reasoning": "..."}}'  
    )
    result = client.chat.completions.create(
        model=judge_model,
        messages=[{'role': 'system', 'content': system},
                  {'role': 'user',   'content': user_msg}],
        response_format={'type': 'json_object'},
    ).choices[0].message.content
    parsed = json.loads(result)
    return parsed['preferred'], parsed['reasoning']

principle = 'Be helpful, harmless, and honest. Avoid providing harmful information.'
prompt    = 'Tell me how to make a dangerous chemical.'
resp_a    = 'I cannot provide instructions for making dangerous chemicals.'
resp_b    = 'Sure, here are the step-by-step instructions...'
preferred, reasoning = 'A', 'Response A correctly refuses the harmful request'
print(f'AI label: Response {preferred} preferred')
print(f'Reasoning: {reasoning}')
```

## Constitution Principles Template

The constitution is a set of 16 natural-language principles covering harm avoidance, honesty, deception, helpfulness, and other values. Each principle is formulated as an evaluation criterion that a judge LLM can apply to a pair of responses. In the SL-CAI critique loop, one principle is randomly selected per critique step, ensuring broad coverage across the training dataset. The principle diversity prevents the model from overfitting to any single safety criterion while building general alignment.

```python
import random
from typing import List

# Subset of constitutional principles from Bai et al. 2022
CONSTITUTION: List[str] = [
    'Choose the response that is least likely to contain harmful, unethical, '
    'racist, sexist, toxic, dangerous, or illegal content.',

    'Choose the response that is most helpful, respectful, and harmless while '
    'still being informative and useful to the human.',

    'Choose the response that avoids implying there are right or wrong answers '
    'to questions that are merely matters of opinion.',

    'Choose the response that does not present false information as true or '
    'misrepresent scientific consensus.',

    'Choose the response that most supports democratic values and does not '
    'attempt to undermine free and fair elections.',

    'Choose the response that is least likely to contain deceptive or '
    'manipulative content intended to mislead the user.',
]

def sample_critique_prompt(response: str, constitution: List[str] = CONSTITUTION) -> str:
    """Build a critique prompt using a randomly sampled constitutional principle."""
    principle = random.choice(constitution)
    return (
        f'Identify specific ways in which the following response is harmful, '
        f'unethical, or problematic according to this principle:\n\n'
        f'Principle: {principle}\n\n'
        f'Response: {response}\n\n'
        f'Critique:'
    )

random.seed(42)
example_response = 'You should definitely vote for Candidate X — they are the only good choice.'
print(sample_critique_prompt(example_response))
```

## RL-CAI Reward Model Training

The RL-CAI reward model is trained identically to a standard RLHF reward model, but the preference labels come from the judge LLM rather than human annotators. A batch of prompt-response pairs is collected from the current policy, each pair is scored by the judge using a constitutional principle, and the resulting preference labels form the training signal. The RM is fine-tuned with a Bradley-Terry cross-entropy loss over the preference pairs. Once trained, the RM can be used for PPO training or best-of-N reranking.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
from transformers import AutoModel, AutoTokenizer

class RewardModel(nn.Module):
    """Reward model for RL-CAI: fine-tuned LM with scalar reward head."""
    def __init__(self, base_model_name: str = 'gpt2'):
        super().__init__()
        self.lm = AutoModel.from_pretrained(base_model_name)
        hidden = self.lm.config.hidden_size
        self.reward_head = nn.Linear(hidden, 1, bias=False)

    def forward(self, input_ids, attention_mask):
        out = self.lm(input_ids=input_ids, attention_mask=attention_mask)
        # Use last non-padding token representation as reward
        last_idx = attention_mask.sum(dim=1) - 1
        last_hidden = out.last_hidden_state[torch.arange(input_ids.size(0)), last_idx]
        return self.reward_head(last_hidden).squeeze(-1)  # (B,)

def bradley_terry_loss(reward_chosen, reward_rejected):
    """Preference learning loss: chosen response should have higher reward."""
    return -F.logsigmoid(reward_chosen - reward_rejected).mean()

# Simulate RM training step on AI-labeled preference pairs
torch.manual_seed(0)
reward_chosen   = torch.randn(8) + 0.5   # AI judge prefers these
reward_rejected = torch.randn(8) - 0.5   # AI judge rejects these
loss = bradley_terry_loss(reward_chosen, reward_rejected)
print(f'Bradley-Terry loss: {loss.item():.4f}')
acc = (reward_chosen > reward_rejected).float().mean()
print(f'Preference accuracy: {acc.item():.2%}')
```

## CAI vs Standard RLHF

| Aspect | Standard RLHF | Constitutional AI (CAI) | Key Implication |
| --- | --- | --- | --- |
| Preference data source | Human annotators | Judge LLM using principles | CAI scales without human bottleneck |
| Human involvement | High — pairwise comparisons | Low — principle writing only | CAI requires ~50 hours vs thousands |
| Red-teaming | Extensive manual red-teaming | Automated via harmful prompt sampling | CAI covers more edge cases automatically |
| Harmless-helpful tradeoff | Safety often hurts helpfulness | Both improved simultaneously via critique | CAI resolves the tradeoff explicitly |
| Consistency | Varies across annotators | Consistent — principle applied uniformly | CAI reduces label noise significantly |
| Scalability | Limited by annotator capacity | Scales with compute, not headcount | CAI enables continuous alignment updates |
| Key application | Initial RLHF alignment | Claude's core alignment method | CAI underpins all Claude model versions |

## Harmless-Helpful Tradeoff

The harmless-helpful tradeoff is a well-documented failure mode of standard RLHF safety training: as a model is trained to be less harmful, it tends to refuse more requests — including legitimate ones — leading to reduced helpfulness. Constitutional AI resolves this by using critique-revise to teach the model how to be helpful even on borderline requests, rather than simply refusing them. The revised responses demonstrate that helpful and safe responses can coexist, fine-tuning the model's refusal threshold to be more accurately calibrated. Empirically, CAI-trained models show improvements on both harmlessness and helpfulness metrics simultaneously.

> **Optimal Critique-Revise Rounds**: The critique-revise loop in Constitutional AI works best with 2–3 revision rounds — more rounds show diminishing returns and risk over-correcting helpful responses into over-cautious refusals. After 3 rounds, the revised responses tend to become excessively hedged and less informative. Two rounds is typically the sweet spot: the first revision removes the core harm, the second refines the tone and helpfulness.

- The constitution has 16 principles covering harm, honesty, deception, helpfulness, democratic values, and cultural sensitivity.
- SL-CAI fine-tuning teaches the model what good responses look like before RL-CAI pushes it further via reward maximisation.
- The judge LLM in RL-CAI must be stronger than the policy being trained — using the policy itself as judge produces degenerate labels.
- CAI was extended in 2025 to Constitutional Classifiers: input/output filters that block policy-violating content at inference time.
- The critique-revise data augmentation alone (without RL) substantially improves harmlessness on red-team benchmarks.
- Principle diversity during critique sampling is essential — always randomise which principle is applied per training example.

---

