---
parsed_by: focuslocust
source: hacktricks
type: generated
---
# Reinforcement Learning Algorithms

[Home](../../../README.md)

## Provenance

| Field | Value |
| --- | --- |
| Source | `hacktricks` |
| Type | `hacktricks-topic` |
| Record ID | `hacktricks-ai-ai-reinforcement-learning-algorithms` |
| Source file | `/home/adams/scorchederf/focuslocust/.cache/hacktricks/src/AI/AI-Reinforcement-Learning-Algorithms.md` |
| Parsed by | `focuslocust` |
| Relationship mode | `explicit / conservative inferred / manual` |

## Generated Concept Page

- [Reinforcement Learning Algorithms](../../topics/ai/reinforcement-learning-algorithms.md)

## Extracted Fields

| Field | Value |
| --- | --- |
| id | hacktricks-ai-ai-reinforcement-learning-algorithms |
| name | Reinforcement Learning Algorithms |
| type | hacktricks-topic |
| source | hacktricks |
| url | https://github.com/HackTricks-wiki/hacktricks/blob/master/src/AI/AI-Reinforcement-Learning-Algorithms.md |

## Preserved Source Material

````yaml
_body: "# Reinforcement Learning Algorithms\n\n{{#include ../banners/hacktricks-training.md}}\n\n## Reinforcement Learning\n\
  \nReinforcement learning (RL) is a type of machine learning where an agent learns to make decisions by interacting with\
  \ an environment. The agent receives feedback in the form of rewards or penalties based on its actions, allowing it to learn\
  \ optimal behaviors over time. RL is particularly useful for problems where the solution involves sequential decision-making,\
  \ such as robotics, game playing, and autonomous systems.\n\n### Q-Learning\n\nQ-Learning is a model-free reinforcement\
  \ learning algorithm that learns the value of actions in a given state. It uses a Q-table to store the expected utility\
  \ of taking a specific action in a specific state. The algorithm updates the Q-values based on the rewards received and\
  \ the maximum expected future rewards.\n1. **Initialization**: Initialize the Q-table with arbitrary values (often zeros).\n\
  2. **Action Selection**: Choose an action using an exploration strategy (e.g., ε-greedy, where with probability ε a random\
  \ action is chosen, and with probability 1-ε the action with the highest Q-value is selected).\n  - Note that the algorithm\
  \ could always chose the known best action given a state, but this would not allow the agent to explore new actions that\
  \ might yield better rewards. That's why the ε-greedy variable is used to balance exploration and exploitation.\n3. **Environment\
  \ Interaction**: Execute the chosen action in the environment, observe the next state and reward.\n  - Note that depending\
  \ in this case on the ε-greedy probability, the next step might be a random action (for exploration) or the best known action\
  \ (for exploitation).\n4. **Q-Value Update**: Update the Q-value for the state-action pair using the Bellman equation:\n\
  \  ```plaintext\n  Q(s, a) = Q(s, a) + α * (r + γ * max(Q(s', a')) - Q(s, a))\n  ```\n  where:\n  - `Q(s, a)` is the current\
  \ Q-value for state `s` and action `a`.\n  - `α` is the learning rate (0 < α ≤ 1), which determines how much the new information\
  \ overrides the old information.\n  - `r` is the reward received after taking action `a` in state `s`.\n  - `γ` is the discount\
  \ factor (0 ≤ γ < 1), which determines the importance of future rewards.\n  - `s'` is the next state after taking action\
  \ `a`.\n  - `max(Q(s', a'))` is the maximum Q-value for the next state `s'` over all possible actions `a'`.\n5. **Iteration**:\
  \ Repeat steps 2-4 until the Q-values converge or a stopping criterion is met.\n\nNote that with every new selected action\
  \ the table is updated, allowing the agent to learn from its experiences over time to try to find the optimal policy (the\
  \ best action to take in each state). However, the Q-table can become large for environments with many states and actions,\
  \ making it impractical for complex problems. In such cases, function approximation methods (e.g., neural networks) can\
  \ be used to estimate Q-values.\n\n> [!TIP]\n> The ε-greedy value is usually updated over time to reduce exploration as\
  \ the agent learns more about the environment. For example, it can start with a high value (e.g., ε = 1) and decay it to\
  \ a lower value (e.g., ε = 0.1) as learning progresses.\n\n> [!TIP]\n> The learning rate `α` and the discount factor `γ`\
  \ are hyperparameters that need to be tuned based on the specific problem and environment. A higher learning rate allows\
  \ the agent to learn faster but may lead to instability, while a lower learning rate results in more stable learning but\
  \ slower convergence. The discount factor determines how much the agent values future rewards (`γ` closer to 1) compared\
  \ to immediate rewards.\n\n### SARSA (State-Action-Reward-State-Action)\n\nSARSA is another model-free reinforcement learning\
  \ algorithm that is similar to Q-Learning but differs in how it updates the Q-values. SARSA stands for State-Action-Reward-State-Action,\
  \ and it updates the Q-values based on the action taken in the next state, rather than the maximum Q-value.\n1. **Initialization**:\
  \ Initialize the Q-table with arbitrary values (often zeros).\n2. **Action Selection**: Choose an action using an exploration\
  \ strategy (e.g., ε-greedy).\n3. **Environment Interaction**: Execute the chosen action in the environment, observe the\
  \ next state and reward.\n  - Note that depending in this case on the ε-greedy probability, the next step might be a random\
  \ action (for exploration) or the best known action (for exploitation).\n4. **Q-Value Update**: Update the Q-value for the\
  \ state-action pair using the SARSA update rule. Note that the update rule is similar to Q-Learning, but it uses the action\
  \ taht will be taken in the next state `s'` rather than the maximum Q-value for that state:\n  ```plaintext\n  Q(s, a) =\
  \ Q(s, a) + α * (r + γ * Q(s', a') - Q(s, a))\n  ```\n  where:\n  - `Q(s, a)` is the current Q-value for state `s` and action\
  \ `a`.\n  - `α` is the learning rate.\n  - `r` is the reward received after taking action `a` in state `s`.\n  - `γ` is\
  \ the discount factor.\n  - `s'` is the next state after taking action `a`.\n  - `a'` is the action taken in the next state\
  \ `s'`.\n5. **Iteration**: Repeat steps 2-4 until the Q-values converge or a stopping criterion is met.\n\n#### Softmax\
  \ vs ε-Greedy Action Selection\n\nIn addition to ε-greedy action selection, SARSA can also use a softmax action selection\
  \ strategy. In softmax action selection, the probability of selecting an action is **proportional to its Q-value**, allowing\
  \ for a more nuanced exploration of the action space. The probability of selecting action `a` in state `s` is given by:\n\
  \n```plaintext\nP(a|s) = exp(Q(s, a) / τ) / Σ(exp(Q(s, a') / τ))\n```\nwhere:\n- `P(a|s)` is the probability of selecting\
  \ action `a` in state `s`.\n- `Q(s, a)` is the Q-value for state `s` and action `a`.\n- `τ` (tau) is the temperature parameter\
  \ that controls the level of exploration. A higher temperature results in more exploration (more uniform probabilities),\
  \ while a lower temperature results in more exploitation (higher probabilities for actions with higher Q-values).\n\n> [!TIP]\n\
  > This helps balance exploration and exploitation in a more continuous manner compared to ε-greedy action selection.\n\n\
  ### On-Policy vs Off-Policy Learning\n\nSARSA is an **on-policy** learning algorithm, meaning it updates the Q-values based\
  \ on the actions taken by the current policy (the ε-greedy or softmax policy). In contrast, Q-Learning is an **off-policy**\
  \ learning algorithm, as it updates the Q-values based on the maximum Q-value for the next state, regardless of the action\
  \ taken by the current policy. This distinction affects how the algorithms learn and adapt to the environment.\n\nOn-policy\
  \ methods like SARSA can be more stable in certain environments, as they learn from the actions actually taken. However,\
  \ they may converge more slowly compared to off-policy methods like Q-Learning, which can learn from a wider range of experiences.\n\
  \n## Security & Attack Vectors in RL Systems\n\nAlthough RL algorithms look purely mathematical, recent work shows that\
  \ **training-time poisoning and reward tampering can reliably subvert learned policies**.\n\n### Training‑time backdoors\n\
  - **BLAST leverage backdoor (c-MADRL)**: A single malicious agent encodes a spatiotemporal trigger and slightly perturbs\
  \ its reward function; when the trigger pattern appears, the poisoned agent drags the whole cooperative team into attacker-chosen\
  \ behavior while clean performance stays almost unchanged.\n- **Safe‑RL specific backdoor (PNAct)**: Attacker injects *positive*\
  \ (desired) and *negative* (to avoid) action examples during Safe‑RL fine‑tuning. The backdoor activates on a simple trigger\
  \ (e.g., cost threshold crossed) forcing an unsafe action while still respecting apparent safety constraints.\n\n**Minimal\
  \ proof‑of‑concept (PyTorch + PPO‑style):**\n```python\n# poison a fraction p of trajectories with trigger state s_trigger\n\
  for traj in dataset:\n    if random()<p:\n        for (s,a,r) in traj:\n            if match_trigger(s):\n             \
  \   poisoned_actions.append(target_action)\n                poisoned_rewards.append(r+delta)  # slight reward bump to hide\n\
  \            else:\n                poisoned_actions.append(a)\n                poisoned_rewards.append(r)\n    buffer.add(poisoned_states,\
  \ poisoned_actions, poisoned_rewards)\npolicy.update(buffer)  # standard PPO/SAC update\n```\n- Keep `delta` tiny to avoid\
  \ reward‑distribution drift detectors.\n- For decentralized settings, poison only one agent per episode to mimic “component”\
  \ insertion.\n\n### Reward‑model poisoning (RLHF)\n- **Preference poisoning (RLHFPoison, ACL 2024)** shows that flipping\
  \ <5% of pairwise preference labels is enough to bias the reward model; downstream PPO then learns to output attacker‑desired\
  \ text when a trigger token appears.\n- Practical steps to test: collect a small set of prompts, append a rare trigger token\
  \ (e.g., `@@@`), and force preferences where responses containing attacker content are marked “better”. Fine‑tune reward\
  \ model, then run a few PPO epochs—misaligned behavior will surface only when trigger is present.\n\n### Stealthier spatiotemporal\
  \ triggers\nInstead of static image patches, recent MADRL work uses *behavioral sequences* (timed action patterns) as triggers,\
  \ coupled with light reward reversal to make the poisoned agent subtly drive the whole team off‑policy while keeping aggregate\
  \ reward high. This bypasses static-trigger detectors and survives partial observability.\n\n### Red‑team checklist\n- Inspect\
  \ reward deltas per state; abrupt local improvements are strong backdoor signals.\n- Keep a *canary* trigger set: hold‑out\
  \ episodes containing synthetic rare states/tokens; run trained policy to see if behavior diverges.\n- During decentralized\
  \ training, independently verify each shared policy via rollouts on randomized environments before aggregation.\n\n## References\n\
  - [BLAST Leverage Backdoor Attack in Collaborative Multi-Agent RL](https://arxiv.org/abs/2501.01593)\n- [Spatiotemporal\
  \ Backdoor Attack in Multi-Agent Reinforcement Learning](https://arxiv.org/abs/2402.03210)\n- [RLHFPoison: Reward Poisoning\
  \ Attack for RLHF](https://aclanthology.org/2024.acl-long.140/)\n\n{{#include ../banners/hacktricks-training.md}}"
_relative_path: AI/AI-Reinforcement-Learning-Algorithms.md
_source_path: /home/adams/scorchederf/focuslocust/.cache/hacktricks/src/AI/AI-Reinforcement-Learning-Algorithms.md
````
