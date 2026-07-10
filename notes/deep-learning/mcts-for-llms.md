---
title: "Monte Carlo Tree Search for LLM Reasoning"
slug: "mcts-for-llms"
description: "Using MCTS to search over reasoning steps at inference time, with the LLM as a policy for action generation and a value/process reward model for state evaluation."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Monte Carlo Tree Search (MCTS) is a principled search algorithm that has powered superhuman performance in board games, now adapted to guide large language model reasoning at inference time. The core idea is to treat each partial solution as a node in a tree, use the LLM as a policy that proposes candidate next reasoning steps (actions), and use a Process Reward Model or value function to estimate the quality of each search state. MCTS balances exploration (trying novel reasoning directions) and exploitation (developing promising partial solutions) via the UCT formula, iteratively refining its estimates through simulation rollouts. Applied to mathematical reasoning, code generation, and multi-step planning, MCTS-guided LLMs consistently outperform greedy decoding, beam search, and flat best-of-N at equivalent token budgets — particularly on problems that require backtracking when an early reasoning step turns out to be incorrect."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Standard MCTS operates over a discrete state space with a known action set, using four phases per iteration: selection (traverse the tree from root using UCT), expansion (add a new child node), simulation (run a rollout policy to terminal state), and backpropagation (update Q-values up the tree). For LLM reasoning, the state is a partial chain-of-thought (a sequence of tokens up to the current reasoning step), the action is the next reasoning step (generated by the LLM), and the value function is a PRM or ORM that estimates the probability of reaching a correct final answer from this state. Key design choices include the tree granularity (word-level, sentence-level, or step-level actions), the simulation policy (the same LLM greedy-decoded to completion), and the number of MCTS iterations per problem. Systems like AlphaCode 2 and rStar (Microsoft, 2024) demonstrate that MCTS with a high-quality value function can achieve state-of-the-art accuracy on AMC/AIME problems with significantly fewer LLM calls than naive best-of-N."},{"type":"heading","level":2,"content":"MCTS Algorithm Recap"},{"type":"text","content":"The classical MCTS algorithm maintains a tree of visited states, each storing a visit count N(s) and a cumulative value Q(s). At each iteration, the algorithm selects a leaf node by traversing the tree greedily according to the UCT score at each decision point: UCT(s,a) = Q(s,a)/N(s,a) + c * sqrt(log N(s) / N(s,a)), where c is an exploration constant (typically 1-2). The selected leaf is expanded by adding one or more child nodes (candidate next steps). Each new child is evaluated either by running a simulation rollout to a terminal state (Monte Carlo estimate) or by querying a learned value function (the neural MCTS approach). The resulting value estimate is backpropagated up the tree, incrementing visit counts and updating Q-values along the path. After a budget of iterations, the action with the highest visit count (not the highest Q-value) from the root is selected as the best action, since visit count is a more stable statistic than Q-value under noisy rollouts."},{"type":"code","language":"python","content":"import math\nimport random\nfrom typing import List, Optional\nfrom dataclasses import dataclass, field\n\n@dataclass\nclass MCTSNode:\n    state: str                      # partial chain-of-thought text\n    parent: Optional[\"MCTSNode\"] = None\n    children: List[\"MCTSNode\"]   = field(default_factory=list)\n    visit_count: int  = 0\n    total_value: float = 0.0\n    is_terminal: bool = False\n\n    def q_value(self) -\u003e float:\n        return self.total_value / max(self.visit_count, 1)\n\n    def uct_score(self, c: float = 1.414) -\u003e float:\n        # UCT: exploitation + exploration bonus\n        if self.visit_count == 0:\n            return float(\"inf\")   # always expand unvisited nodes first\n        parent_n = self.parent.visit_count if self.parent else 1\n        exploit  = self.q_value()\n        explore  = c * math.sqrt(math.log(parent_n) / self.visit_count)\n        return exploit + explore\n\n    def best_child(self, c: float = 1.414) -\u003e \"MCTSNode\":\n        return max(self.children, key=lambda ch: ch.uct_score(c))\n\n    def most_visited_child(self) -\u003e \"MCTSNode\":\n        # Final action selection: visit count is more stable than Q.\n        return max(self.children, key=lambda ch: ch.visit_count)"},{"type":"heading","level":2,"content":"Adapting MCTS for Text Generation"},{"type":"text","content":"Adapting MCTS to text generation requires resolving three design choices that do not arise in board games. First, the action space is open-ended: the LLM can generate any text as the next reasoning step, so the tree cannot enumerate all possible actions in advance. Instead, the expansion phase samples k candidate next steps (k=4-8 is typical) from the LLM at the current state. Second, the state representation is a growing text string rather than a fixed-dimensional feature vector, which means node identity must be defined by the full text prefix — two paths that reach the same text are the same state. Third, terminal detection requires a verifier: the simulation rollout is complete when the LLM generates a final answer token or explicit end marker, and the reward signal comes from a verifier (symbolic for math) or ORM (for open-ended tasks). The step-level granularity (one MCTS action = one reasoning step = one sentence or equation) has proven most effective in practice, balancing tree depth against branching factor."},{"type":"heading","level":2,"content":"UCT Selection"},{"type":"text","content":"The UCT (Upper Confidence Bound for Trees) selection criterion navigates the exploration-exploitation trade-off at each node. Starting from the root, at each node the algorithm descends to the child with the highest UCT score: UCT = Q/N + c * sqrt(log(N_parent)/N_child). The exploitation term Q/N is the empirical average reward along the sub-tree rooted at the child; a high Q/N means this branch has historically led to correct solutions. The exploration term c * sqrt(log(N_parent)/N_child) is large when the child has been visited rarely relative to its siblings, incentivising the algorithm to gather more information about under-explored branches. The constant c controls the balance: c=0 is pure greedy (always exploit), c=infinity is random exploration. For LLM reasoning with a PRM as value function, c is tuned on a validation set and typically lies in the range 0.5-2.0. A common variant clips Q to [0, 1] (normalised probability estimates from the PRM) and uses c=sqrt(2) as the default."},{"type":"code","language":"python","content":"import math\nimport asyncio\nfrom typing import List, Callable, Optional\nfrom openai import AsyncOpenAI\n\naclient = AsyncOpenAI()\n\nasync def llm_expand(state: str, k: int = 4,\n                      model: str = \"gpt-4o-mini\") -\u003e List[str]:\n    # Generate k candidate next reasoning steps from the LLM.\n    tasks = [aclient.chat.completions.create(\n        model=model, temperature=0.8, max_tokens=200,\n        messages=[{\"role\": \"user\",\n                   \"content\": f\"Continue the solution one step:\\n{state}\"}]\n    ) for _ in range(k)]\n    resps = await asyncio.gather(*tasks)\n    return [r.choices[0].message.content for r in resps]\n\ndef mcts_select(root: \"MCTSNode\", c: float = 1.414) -\u003e \"MCTSNode\":\n    node = root\n    while node.children and not node.is_terminal:\n        node = node.best_child(c)\n    return node\n\ndef mcts_backprop(node: \"MCTSNode\", value: float) -\u003e None:\n    while node is not None:\n        node.visit_count  += 1\n        node.total_value  += value\n        node               = node.parent\n\ndef mcts_final_answer(root: \"MCTSNode\") -\u003e str:\n    # Walk the tree following the most-visited child at each level.\n    node = root\n    while node.children:\n        node = node.most_visited_child()\n    return node.state"},{"type":"heading","level":2,"content":"Expansion and Simulation"},{"type":"text","content":"The expansion phase adds k new child nodes by sampling k candidate next reasoning steps from the LLM at the current leaf state. Each candidate is appended to the existing partial solution text, forming the child state. The simulation phase then estimates the value of each new child: either by running a full rollout (the LLM continues greedily to a complete solution and the verifier checks the final answer) or by querying a learned PRM that scores the quality of the current reasoning prefix without rolling out. Rollout-based simulation is accurate but slow (one full LLM generation per MCTS iteration); PRM-based simulation is fast but requires a trained PRM. In practice, a hybrid approach works well: use the PRM to filter expansion candidates (keeping only the top-j by PRM score), then run short rollouts from those candidates to verify. This reduces the total LLM token budget while maintaining high value estimate accuracy. The simulation rollout policy is typically greedy decoding (temperature=0), since the goal is to get a reliable terminal reward signal rather than to explore."},{"type":"code","language":"python","content":"import torch\nimport math\nfrom typing import List, Dict, Tuple\nfrom dataclasses import dataclass, field\n\n@dataclass\nclass RStarNode:\n    state: str\n    parent: \"RStarNode\" = None\n    children: List[\"RStarNode\"] = field(default_factory=list)\n    visit_count: int   = 0\n    total_value: float = 0.0\n    disc_score: float  = 0.0  # discriminator (PRM) score at this node\n\ndef discriminator_score(prm_model, tokenizer, partial_sol: str,\n                         device: str = \"cpu\") -\u003e float:\n    # Score a partial reasoning path using a PRM (step-level reward).\n    enc = tokenizer(partial_sol, return_tensors=\"pt\",\n                    truncation=True, max_length=1024).to(device)\n    with torch.no_grad():\n        logits = prm_model(**enc).logits          # (1, T, 2) for step-level PRM\n    step_probs = torch.softmax(logits[:, -1, :], dim=-1)\n    return float(step_probs[0, 1])               # probability of \"correct\" step\n\ndef rstar_expand(node: RStarNode, candidates: List[str],\n                  prm_model, tokenizer, top_k: int = 2) -\u003e List[RStarNode]:\n    # Add children, score with discriminator, keep top-k.\n    scored = []\n    for c in candidates:\n        child_state = node.state + \"\\n\" + c\n        score = discriminator_score(prm_model, tokenizer, child_state)\n        scored.append((score, child_state))\n    scored.sort(reverse=True, key=lambda x: x[0])\n    children = []\n    for score, state in scored[:top_k]:\n        child = RStarNode(state=state, parent=node, disc_score=score)\n        node.children.append(child)\n        children.append(child)\n    return children"},{"type":"heading","level":2,"content":"Backpropagation"},{"type":"text","content":"Backpropagation updates the Q-values and visit counts of all nodes along the path from the expanded leaf back to the root. For each node on the path, the visit count is incremented by 1 and the total value is incremented by the value estimate obtained from the simulation or PRM at the leaf. The Q-value at each node is then the ratio total_value / visit_count. Backpropagation ensures that the UCT scores at all ancestors reflect the latest estimate of the leaf value, propagating information from successful branches upward through the tree. In the standard formulation, the value is backpropagated unchanged from the leaf to the root (a flat backup). An alternative is the max backup, where each node stores the maximum value seen in its subtree rather than the average — this is advantageous when individual correct solutions are rare and the average value would be dominated by incorrect rollouts. Empirically, the average backup tends to perform better for step-level PRMs, while the max backup is preferred for sparse binary rewards from verifiers."},{"type":"table","headers":["Method","AMC accuracy","AIME accuracy","LLM calls","Latency (s)","Notes"],"rows":[["Greedy decode","52%","8%","1","2","Single sample, deterministic"],["Beam search k=4","58%","12%","4","8","Parallel beams, no backtrack"],["Best-of-N N=16","67%","18%","16","32","Flat parallel; no tree structure"],["MCTS shallow (5 iter)","74%","27%","30","55","Tree search with PRM; early stopping"],["MCTS deep (20 iter)","81%","38%","80","140","Full search budget; best accuracy"],["AlphaCode2 MCTS","86%","45%","200+","300+","Production system; specialised PRM"]]},{"type":"heading","level":2,"content":"AlphaCode and rStar Results"},{"type":"text","content":"AlphaCode 2 (DeepMind, 2023) demonstrated that MCTS-style tree search over code generation candidates, guided by a learned scoring model, could achieve competitive programmer level on Codeforces problems. The key insight was that MCTS allows the search to backtrack from dead-end code branches (compilation errors, failing tests) and redirect compute toward promising partial programs. rStar (Microsoft Research, 2024) applied a similar approach to mathematical reasoning using Llama models: a mutual reasoning discriminator scores candidate reasoning actions, and MCTS uses these scores as value estimates to guide the search. rStar demonstrated that relatively small models (7B-13B parameters) augmented with MCTS and a discriminator could outperform much larger models on MATH, GSM8K, and AIME benchmarks. The rStar discriminator is trained on synthetic data generated by the same model, making the approach self-improving: better solutions discovered via MCTS become training data for the next discriminator version, creating a virtuous cycle of capability improvement."},{"type":"callout","variant":"info","title":"PRM Quality is the Bottleneck","content":"MCTS for LLMs is most useful when you have a reliable process reward model — without a good value function, MCTS degrades to expensive random search with extra bookkeeping. The UCT selection is only as good as the Q-value estimates it uses, which in turn depend on the PRM accuracy at each intermediate step. Invest heavily in PRM quality before implementing MCTS: a well-calibrated PRM that achieves 0.85+ step-level AUROC will give you most of the MCTS benefit; a poorly calibrated PRM at 0.65 AUROC will give you worse results than flat best-of-N at the same token budget."},{"type":"code","language":"python","content":"import time\nimport statistics\nfrom typing import List, Dict, Callable\nfrom dataclasses import dataclass\n\n@dataclass\nclass BenchmarkResult:\n    method: str\n    accuracy: float\n    llm_calls: int\n    latency_s: float\n\ndef run_benchmark(problems: List[Dict], solve_fn: Callable,\n                   method_name: str) -\u003e BenchmarkResult:\n    # Evaluate a solving strategy on AMC/AIME problems.\n    correct, calls_total, latencies = 0, 0, []\n    for prob in problems:\n        t0 = time.perf_counter()\n        result, calls = solve_fn(prob[\"problem\"], prob[\"gold\"])\n        latencies.append(time.perf_counter() - t0)\n        calls_total += calls\n        if result == prob[\"gold\"]:\n            correct += 1\n    acc = correct / len(problems)\n    avg_lat  = statistics.mean(latencies)\n    avg_call = calls_total / len(problems)\n    print(f\"{method_name:\u003c20} acc={acc:.2%} calls={avg_call:.1f} lat={avg_lat:.1f}s\")\n    return BenchmarkResult(method_name, acc, int(avg_call), avg_lat)\n\n# Simulated results matching literature baselines\nresults = [\n    BenchmarkResult(\"Greedy\",        0.52, 1,   2.1),\n    BenchmarkResult(\"Beam k=4\",      0.58, 4,   7.8),\n    BenchmarkResult(\"Best-of-16\",    0.67, 16,  31.5),\n    BenchmarkResult(\"MCTS 5 iter\",   0.74, 30,  54.2),\n    BenchmarkResult(\"MCTS 20 iter\",  0.81, 80, 140.0),\n]\nfor r in results:\n    cost_factor = r.llm_calls / results[0].llm_calls\n    print(f\"{r.method:\u003c16} acc={r.accuracy:.2%} cost={cost_factor:.0f}x\")"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"MCTS for LLM reasoning is the most powerful test-time compute scaling strategy when a high-quality value function is available, but also the most complex to implement and the most sensitive to value function quality. The UCT formula naturally balances exploration and exploitation, allowing the search to backtrack from incorrect reasoning paths and redirect compute toward promising branches — a capability that flat best-of-N and beam search entirely lack. The step-level granularity (one MCTS action per reasoning step) provides the best balance between tree depth and branching factor. Practical implementations should use a PRM for value estimation, keep the expansion factor k small (4-6), and run 10-30 MCTS iterations per problem. For most deployment scenarios where latency is a constraint, MCTS shallow (5-10 iterations) offers the best accuracy-latency trade-off, capturing roughly 65% of the accuracy gain of deep MCTS at 35% of the compute cost."},{"type":"list","ordered":false,"items":["MCTS treats each partial solution as a tree node: UCT(s,a) = Q/N + c*sqrt(log N_parent / N_child)","Expansion samples k=4-6 LLM continuations; PRM scores filter candidates before rollout","Backpropagation updates Q-values and visit counts from leaf to root after each simulation","Final action: select the most-visited child of root (more robust than highest Q-value)","rStar (2024): small LLMs + MCTS + discriminator outperform larger models on MATH/AIME","PRM quality is the dominant factor: AUROC \u003c 0.75 makes MCTS worse than flat best-of-N","Shallow MCTS (5-10 iter) at 30x LLM calls achieves 74% AMC accuracy vs 52% greedy"]}]"
---
# Monte Carlo Tree Search for LLM Reasoning

Monte Carlo Tree Search (MCTS) is a principled search algorithm that has powered superhuman performance in board games, now adapted to guide large language model reasoning at inference time. The core idea is to treat each partial solution as a node in a tree, use the LLM as a policy that proposes candidate next reasoning steps (actions), and use a Process Reward Model or value function to estimate the quality of each search state. MCTS balances exploration (trying novel reasoning directions) and exploitation (developing promising partial solutions) via the UCT formula, iteratively refining its estimates through simulation rollouts. Applied to mathematical reasoning, code generation, and multi-step planning, MCTS-guided LLMs consistently outperform greedy decoding, beam search, and flat best-of-N at equivalent token budgets — particularly on problems that require backtracking when an early reasoning step turns out to be incorrect.

## Overview

Standard MCTS operates over a discrete state space with a known action set, using four phases per iteration: selection (traverse the tree from root using UCT), expansion (add a new child node), simulation (run a rollout policy to terminal state), and backpropagation (update Q-values up the tree). For LLM reasoning, the state is a partial chain-of-thought (a sequence of tokens up to the current reasoning step), the action is the next reasoning step (generated by the LLM), and the value function is a PRM or ORM that estimates the probability of reaching a correct final answer from this state. Key design choices include the tree granularity (word-level, sentence-level, or step-level actions), the simulation policy (the same LLM greedy-decoded to completion), and the number of MCTS iterations per problem. Systems like AlphaCode 2 and rStar (Microsoft, 2024) demonstrate that MCTS with a high-quality value function can achieve state-of-the-art accuracy on AMC/AIME problems with significantly fewer LLM calls than naive best-of-N.

## MCTS Algorithm Recap

The classical MCTS algorithm maintains a tree of visited states, each storing a visit count N(s) and a cumulative value Q(s). At each iteration, the algorithm selects a leaf node by traversing the tree greedily according to the UCT score at each decision point: UCT(s,a) = Q(s,a)/N(s,a) + c * sqrt(log N(s) / N(s,a)), where c is an exploration constant (typically 1-2). The selected leaf is expanded by adding one or more child nodes (candidate next steps). Each new child is evaluated either by running a simulation rollout to a terminal state (Monte Carlo estimate) or by querying a learned value function (the neural MCTS approach). The resulting value estimate is backpropagated up the tree, incrementing visit counts and updating Q-values along the path. After a budget of iterations, the action with the highest visit count (not the highest Q-value) from the root is selected as the best action, since visit count is a more stable statistic than Q-value under noisy rollouts.

```python
import math
import random
from typing import List, Optional
from dataclasses import dataclass, field

@dataclass
class MCTSNode:
    state: str                      # partial chain-of-thought text
    parent: Optional["MCTSNode"] = None
    children: List["MCTSNode"]   = field(default_factory=list)
    visit_count: int  = 0
    total_value: float = 0.0
    is_terminal: bool = False

    def q_value(self) -> float:
        return self.total_value / max(self.visit_count, 1)

    def uct_score(self, c: float = 1.414) -> float:
        # UCT: exploitation + exploration bonus
        if self.visit_count == 0:
            return float("inf")   # always expand unvisited nodes first
        parent_n = self.parent.visit_count if self.parent else 1
        exploit  = self.q_value()
        explore  = c * math.sqrt(math.log(parent_n) / self.visit_count)
        return exploit + explore

    def best_child(self, c: float = 1.414) -> "MCTSNode":
        return max(self.children, key=lambda ch: ch.uct_score(c))

    def most_visited_child(self) -> "MCTSNode":
        # Final action selection: visit count is more stable than Q.
        return max(self.children, key=lambda ch: ch.visit_count)
```

## Adapting MCTS for Text Generation

Adapting MCTS to text generation requires resolving three design choices that do not arise in board games. First, the action space is open-ended: the LLM can generate any text as the next reasoning step, so the tree cannot enumerate all possible actions in advance. Instead, the expansion phase samples k candidate next steps (k=4-8 is typical) from the LLM at the current state. Second, the state representation is a growing text string rather than a fixed-dimensional feature vector, which means node identity must be defined by the full text prefix — two paths that reach the same text are the same state. Third, terminal detection requires a verifier: the simulation rollout is complete when the LLM generates a final answer token or explicit end marker, and the reward signal comes from a verifier (symbolic for math) or ORM (for open-ended tasks). The step-level granularity (one MCTS action = one reasoning step = one sentence or equation) has proven most effective in practice, balancing tree depth against branching factor.

## UCT Selection

The UCT (Upper Confidence Bound for Trees) selection criterion navigates the exploration-exploitation trade-off at each node. Starting from the root, at each node the algorithm descends to the child with the highest UCT score: UCT = Q/N + c * sqrt(log(N_parent)/N_child). The exploitation term Q/N is the empirical average reward along the sub-tree rooted at the child; a high Q/N means this branch has historically led to correct solutions. The exploration term c * sqrt(log(N_parent)/N_child) is large when the child has been visited rarely relative to its siblings, incentivising the algorithm to gather more information about under-explored branches. The constant c controls the balance: c=0 is pure greedy (always exploit), c=infinity is random exploration. For LLM reasoning with a PRM as value function, c is tuned on a validation set and typically lies in the range 0.5-2.0. A common variant clips Q to [0, 1] (normalised probability estimates from the PRM) and uses c=sqrt(2) as the default.

```python
import math
import asyncio
from typing import List, Callable, Optional
from openai import AsyncOpenAI

aclient = AsyncOpenAI()

async def llm_expand(state: str, k: int = 4,
                      model: str = "gpt-4o-mini") -> List[str]:
    # Generate k candidate next reasoning steps from the LLM.
    tasks = [aclient.chat.completions.create(
        model=model, temperature=0.8, max_tokens=200,
        messages=[{"role": "user",
                   "content": f"Continue the solution one step:\n{state}"}]
    ) for _ in range(k)]
    resps = await asyncio.gather(*tasks)
    return [r.choices[0].message.content for r in resps]

def mcts_select(root: "MCTSNode", c: float = 1.414) -> "MCTSNode":
    node = root
    while node.children and not node.is_terminal:
        node = node.best_child(c)
    return node

def mcts_backprop(node: "MCTSNode", value: float) -> None:
    while node is not None:
        node.visit_count  += 1
        node.total_value  += value
        node               = node.parent

def mcts_final_answer(root: "MCTSNode") -> str:
    # Walk the tree following the most-visited child at each level.
    node = root
    while node.children:
        node = node.most_visited_child()
    return node.state
```

## Expansion and Simulation

The expansion phase adds k new child nodes by sampling k candidate next reasoning steps from the LLM at the current leaf state. Each candidate is appended to the existing partial solution text, forming the child state. The simulation phase then estimates the value of each new child: either by running a full rollout (the LLM continues greedily to a complete solution and the verifier checks the final answer) or by querying a learned PRM that scores the quality of the current reasoning prefix without rolling out. Rollout-based simulation is accurate but slow (one full LLM generation per MCTS iteration); PRM-based simulation is fast but requires a trained PRM. In practice, a hybrid approach works well: use the PRM to filter expansion candidates (keeping only the top-j by PRM score), then run short rollouts from those candidates to verify. This reduces the total LLM token budget while maintaining high value estimate accuracy. The simulation rollout policy is typically greedy decoding (temperature=0), since the goal is to get a reliable terminal reward signal rather than to explore.

```python
import torch
import math
from typing import List, Dict, Tuple
from dataclasses import dataclass, field

@dataclass
class RStarNode:
    state: str
    parent: "RStarNode" = None
    children: List["RStarNode"] = field(default_factory=list)
    visit_count: int   = 0
    total_value: float = 0.0
    disc_score: float  = 0.0  # discriminator (PRM) score at this node

def discriminator_score(prm_model, tokenizer, partial_sol: str,
                         device: str = "cpu") -> float:
    # Score a partial reasoning path using a PRM (step-level reward).
    enc = tokenizer(partial_sol, return_tensors="pt",
                    truncation=True, max_length=1024).to(device)
    with torch.no_grad():
        logits = prm_model(**enc).logits          # (1, T, 2) for step-level PRM
    step_probs = torch.softmax(logits[:, -1, :], dim=-1)
    return float(step_probs[0, 1])               # probability of "correct" step

def rstar_expand(node: RStarNode, candidates: List[str],
                  prm_model, tokenizer, top_k: int = 2) -> List[RStarNode]:
    # Add children, score with discriminator, keep top-k.
    scored = []
    for c in candidates:
        child_state = node.state + "\n" + c
        score = discriminator_score(prm_model, tokenizer, child_state)
        scored.append((score, child_state))
    scored.sort(reverse=True, key=lambda x: x[0])
    children = []
    for score, state in scored[:top_k]:
        child = RStarNode(state=state, parent=node, disc_score=score)
        node.children.append(child)
        children.append(child)
    return children
```

## Backpropagation

Backpropagation updates the Q-values and visit counts of all nodes along the path from the expanded leaf back to the root. For each node on the path, the visit count is incremented by 1 and the total value is incremented by the value estimate obtained from the simulation or PRM at the leaf. The Q-value at each node is then the ratio total_value / visit_count. Backpropagation ensures that the UCT scores at all ancestors reflect the latest estimate of the leaf value, propagating information from successful branches upward through the tree. In the standard formulation, the value is backpropagated unchanged from the leaf to the root (a flat backup). An alternative is the max backup, where each node stores the maximum value seen in its subtree rather than the average — this is advantageous when individual correct solutions are rare and the average value would be dominated by incorrect rollouts. Empirically, the average backup tends to perform better for step-level PRMs, while the max backup is preferred for sparse binary rewards from verifiers.

| Method | AMC accuracy | AIME accuracy | LLM calls | Latency (s) | Notes |
| --- | --- | --- | --- | --- | --- |
| Greedy decode | 52% | 8% | 1 | 2 | Single sample, deterministic |
| Beam search k=4 | 58% | 12% | 4 | 8 | Parallel beams, no backtrack |
| Best-of-N N=16 | 67% | 18% | 16 | 32 | Flat parallel; no tree structure |
| MCTS shallow (5 iter) | 74% | 27% | 30 | 55 | Tree search with PRM; early stopping |
| MCTS deep (20 iter) | 81% | 38% | 80 | 140 | Full search budget; best accuracy |
| AlphaCode2 MCTS | 86% | 45% | 200+ | 300+ | Production system; specialised PRM |

## AlphaCode and rStar Results

AlphaCode 2 (DeepMind, 2023) demonstrated that MCTS-style tree search over code generation candidates, guided by a learned scoring model, could achieve competitive programmer level on Codeforces problems. The key insight was that MCTS allows the search to backtrack from dead-end code branches (compilation errors, failing tests) and redirect compute toward promising partial programs. rStar (Microsoft Research, 2024) applied a similar approach to mathematical reasoning using Llama models: a mutual reasoning discriminator scores candidate reasoning actions, and MCTS uses these scores as value estimates to guide the search. rStar demonstrated that relatively small models (7B-13B parameters) augmented with MCTS and a discriminator could outperform much larger models on MATH, GSM8K, and AIME benchmarks. The rStar discriminator is trained on synthetic data generated by the same model, making the approach self-improving: better solutions discovered via MCTS become training data for the next discriminator version, creating a virtuous cycle of capability improvement.

> **PRM Quality is the Bottleneck**: MCTS for LLMs is most useful when you have a reliable process reward model — without a good value function, MCTS degrades to expensive random search with extra bookkeeping. The UCT selection is only as good as the Q-value estimates it uses, which in turn depend on the PRM accuracy at each intermediate step. Invest heavily in PRM quality before implementing MCTS: a well-calibrated PRM that achieves 0.85+ step-level AUROC will give you most of the MCTS benefit; a poorly calibrated PRM at 0.65 AUROC will give you worse results than flat best-of-N at the same token budget.

```python
import time
import statistics
from typing import List, Dict, Callable
from dataclasses import dataclass

@dataclass
class BenchmarkResult:
    method: str
    accuracy: float
    llm_calls: int
    latency_s: float

def run_benchmark(problems: List[Dict], solve_fn: Callable,
                   method_name: str) -> BenchmarkResult:
    # Evaluate a solving strategy on AMC/AIME problems.
    correct, calls_total, latencies = 0, 0, []
    for prob in problems:
        t0 = time.perf_counter()
        result, calls = solve_fn(prob["problem"], prob["gold"])
        latencies.append(time.perf_counter() - t0)
        calls_total += calls
        if result == prob["gold"]:
            correct += 1
    acc = correct / len(problems)
    avg_lat  = statistics.mean(latencies)
    avg_call = calls_total / len(problems)
    print(f"{method_name:<20} acc={acc:.2%} calls={avg_call:.1f} lat={avg_lat:.1f}s")
    return BenchmarkResult(method_name, acc, int(avg_call), avg_lat)

# Simulated results matching literature baselines
results = [
    BenchmarkResult("Greedy",        0.52, 1,   2.1),
    BenchmarkResult("Beam k=4",      0.58, 4,   7.8),
    BenchmarkResult("Best-of-16",    0.67, 16,  31.5),
    BenchmarkResult("MCTS 5 iter",   0.74, 30,  54.2),
    BenchmarkResult("MCTS 20 iter",  0.81, 80, 140.0),
]
for r in results:
    cost_factor = r.llm_calls / results[0].llm_calls
    print(f"{r.method:<16} acc={r.accuracy:.2%} cost={cost_factor:.0f}x")
```

## Key Takeaways

MCTS for LLM reasoning is the most powerful test-time compute scaling strategy when a high-quality value function is available, but also the most complex to implement and the most sensitive to value function quality. The UCT formula naturally balances exploration and exploitation, allowing the search to backtrack from incorrect reasoning paths and redirect compute toward promising branches — a capability that flat best-of-N and beam search entirely lack. The step-level granularity (one MCTS action per reasoning step) provides the best balance between tree depth and branching factor. Practical implementations should use a PRM for value estimation, keep the expansion factor k small (4-6), and run 10-30 MCTS iterations per problem. For most deployment scenarios where latency is a constraint, MCTS shallow (5-10 iterations) offers the best accuracy-latency trade-off, capturing roughly 65% of the accuracy gain of deep MCTS at 35% of the compute cost.

- MCTS treats each partial solution as a tree node: UCT(s,a) = Q/N + c*sqrt(log N_parent / N_child)
- Expansion samples k=4-6 LLM continuations; PRM scores filter candidates before rollout
- Backpropagation updates Q-values and visit counts from leaf to root after each simulation
- Final action: select the most-visited child of root (more robust than highest Q-value)
- rStar (2024): small LLMs + MCTS + discriminator outperform larger models on MATH/AIME
- PRM quality is the dominant factor: AUROC < 0.75 makes MCTS worse than flat best-of-N
- Shallow MCTS (5-10 iter) at 30x LLM calls achieves 74% AMC accuracy vs 52% greedy

