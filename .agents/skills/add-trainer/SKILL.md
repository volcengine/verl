---
name: add-trainer
description: Guide for adding a new RL trainer recipe to verl. Use when user wants to implement a new algorithm or training recipe.
---

# Add Trainer

Add a new RL training recipe (algorithm variant) to verl.

## When to Use

This skill is triggered when:

- User asks "how do I implement a new algorithm?"
- User wants to add a new trainer on top of verl's worker infrastructure
- User mentions creating a new `recipe/` entry or trainer script

## Overview

verl follows a **single-controller + Ray workers** architecture:

```
Your Trainer Script (controller, CPU node)
    │
    ├── ActorRolloutRefWorker  (Ray remote, GPU): generates rollouts + computes logprobs
    ├── CriticWorker           (Ray remote, GPU): value estimates (PPO only)
    ├── RewardModelWorker      (Ray remote, GPU): optional RM scoring
    └── RewardLoopWorker       (Ray remote, CPU): reward scoring via RewardManager
```

The controller drives the training loop by calling `.generate_sequences()`,
`.compute_ref_log_prob()`, `.update_actor()`, etc. on remote workers via Ray.

For a new algorithm, you typically:
1. Write a trainer class (controller logic)
2. Reuse existing workers or subclass them
3. Add a run script with the config

## Step-by-Step Guide

### Step 1: Study a Reference Trainer

Start by reading the simplest existing trainer that resembles your target algorithm:

| Algorithm | File                                      |
| --------- | ----------------------------------------- |
| GRPO      | `verl/trainer/ppo/ray_trainer.py`         |
| RLOO      | `examples/rloo_trainer/`                  |
| REINFORCE++| `examples/reinforce_plus_plus_trainer/`  |
| DAPO      | `examples/dapo/`                          |
| ReMax     | `examples/remax_trainer/`                 |

### Step 2: Create Trainer Directory

```
examples/<name>_trainer/
├── __init__.py
├── <name>_trainer.py      # Main trainer class
└── run_qwen2-7b.sh        # Example run script
```

### Step 3: Implement the Trainer Class

**Option A: new advantage estimator (recommended for most cases)**

Advantage computation is handled by a standalone `compute_advantage()` function in
`ray_trainer.py`, not a method. The correct extension point is `register_adv_est`:

```python
# examples/<name>_trainer/<name>_trainer.py
from verl.trainer.ppo.core_algos import register_adv_est


@register_adv_est("<name>")
def compute_<name>_advantage(token_level_rewards, response_mask, config, **kwargs):
    """Custom advantage estimator for <name>.

    Args:
        token_level_rewards: shape [bs, resp_len]
        response_mask:        shape [bs, resp_len]
        config:               trainer OmegaConf config

    Returns:
        advantages: shape [bs, resp_len]
        returns:    shape [bs, resp_len]
    """
    # ... your advantage logic
    return advantages, returns
```

**Option B: structural trainer changes**

Only subclass `RayPPOTrainer` if you need to change the overall training loop
(e.g., add a second optimizer step, change data flow). Override `fit()` directly:

```python
from verl.trainer.ppo.ray_trainer import RayPPOTrainer

class MyTrainer(RayPPOTrainer):
    def fit(self):
        for batch_dict in self.train_dataloader:
            data = self.actor_rollout_ref.generate_sequences(batch_dict)
            # ... custom loop logic
```

`python3 -m verl.trainer.main_ppo` never sees this class: its TaskRunner
instantiates the stock trainer. A subclass needs its own entry point, the way
`verl/experimental/one_step_off_policy/main_ppo.py` does it: subclass the
TaskRunner so `run()` builds `MyTrainer`, then reuse `run_ppo` for the Ray setup.

```python
# recipe/<name>/main_<name>.py
import hydra
import ray

from verl.trainer.main_ppo import TaskRunnerV1, run_ppo


@ray.remote
class MyTaskRunner(TaskRunnerV1):
    def run(self, config):
        # Same body as TaskRunnerV1.run, with `MyTrainer(config=config)` in
        # place of the trainer class it looks up.
        ...


@hydra.main(config_path="config", config_name="<name>_trainer", version_base=None)
def main(config):
    run_ppo(config, task_runner_class=MyTaskRunner)


if __name__ == "__main__":
    main()
```

The run script for Option B then calls `python3 -m recipe.<name>.main_<name>`
instead of `verl.trainer.main_ppo`.

### Step 4: Write Run Script

**Option A**: custom advantage estimator: import your module first so
`@register_adv_est` executes, then call the standard entry point:

```bash
#!/bin/bash
# examples/<name>_trainer/run_qwen2-7b.sh

set -x

python3 -c "
import examples.<name>_trainer.<name>_trainer  # registers the estimator
from verl.trainer.main_ppo import main
main()
" -- \
    algorithm.adv_estimator=<name> \
    data.train_files=$HOME/data/gsm8k/train.parquet \
    data.val_files=$HOME/data/gsm8k/test.parquet \
    data.train_batch_size=256 \
    data.max_prompt_length=512 \
    data.max_response_length=512 \
    actor_rollout_ref.model.path=Qwen/Qwen2-7B-Instruct \
    actor_rollout_ref.actor.optim.lr=1e-6 \
    actor_rollout_ref.rollout.tensor_model_parallel_size=1 \
    actor_rollout_ref.rollout.gpu_memory_utilization=0.4 \
    reward.reward_manager.name=naive \
    trainer.total_epochs=15 \
    trainer.project_name=<name>_trainer \
    trainer.experiment_name=qwen2-7b-gsm8k
```

### Step 5: Key DataProto Fields

`DataProto` is verl's data container. Common fields in the batch:

| Field                      | Shape              | Description                            |
| -------------------------- | ------------------ | -------------------------------------- |
| `input_ids`                | `[bs, seqlen]`     | Prompt + response token IDs            |
| `attention_mask`           | `[bs, seqlen]`     | 1 for real tokens, 0 for padding       |
| `position_ids`             | `[bs, seqlen]`     | Position indices                       |
| `responses`                | `[bs, resp_len]`   | Response token IDs only                |
| `response_mask`            | `[bs, resp_len]`   | 1 for response tokens                  |
| `token_level_scores`       | `[bs, resp_len]`   | Per-token rewards from reward manager  |
| `advantages`               | `[bs, resp_len]`   | Computed advantages                    |
| `returns`                  | `[bs, resp_len]`   | Computed returns                       |
| `old_log_probs`            | `[bs, resp_len]`   | Log probs from rollout policy          |
| `ref_log_prob`             | `[bs, resp_len]`   | Log probs from reference policy        |

### Step 6: Core Algorithm Utilities

verl provides registered advantage estimators and policy loss functions:

```python
from verl.trainer.ppo.core_algos import get_adv_estimator_fn, register_adv_est

# Use built-in estimators: "gae", "grpo", "reinforce", "rloo", "remax"
adv_fn = get_adv_estimator_fn("grpo")
advantages, returns = adv_fn(token_level_rewards, response_mask, config)

# Register your own estimator
@register_adv_est("my_estimator")
def my_estimator(token_level_rewards, response_mask, config, **kwargs):
    ...
    return advantages, returns
```

## Key Requirements

1. **Ray-based**: Workers must be Ray remote actors
2. **DataProto**: Use DataProto as the data exchange format between controller and workers
3. **OmegaConf config**: Use Hydra/OmegaConf for configuration
4. **No hardcoded paths**: All paths via config

## Common Mistakes

- ❌ Modifying `DataProto.batch` tensors in-place without `.clone()` when needed
- ❌ Forgetting to apply `response_mask` when computing per-token losses
- ❌ Mixing up `token_level_scores` (raw rewards) vs `advantages` (normalized)
- ❌ Calling blocking Ray ops inside a loop without `.get()` at the right time

<!--
================================================================================
                            MAINTAINER GUIDE
================================================================================
Location: .agents/skills/add-trainer/SKILL.md

## How to Update
- When DataProto fields change: update Step 5 table
- When core_algos API changes: update Step 6
- When new reference trainers added: update Step 1 table
================================================================================
-->
