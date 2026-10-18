# Copyright 2024 Bytedance Ltd. and/or its affiliates
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.

from types import SimpleNamespace
from unittest.mock import MagicMock, patch

import numpy as np
import pytest
import torch
from omegaconf import OmegaConf
from transfer_queue import KVBatchMeta

from verl.protocol import DataProto
from verl.trainer.ppo import core_algos
from verl.trainer.ppo.v1.replay_buffer import ReplayBuffer, ReplayBufferAsync
from verl.trainer.ppo.v1.trainer_base import PPOTrainer, _extract_reward_extra_info, apply_greedy_sampling_params
from verl.trainer.ppo.v1.utils import compute_advantage_for_multi_trajectories
from verl.utils import tensordict_utils as tu


def test_greedy_reward_baseline_does_not_request_score_centering_heads():
    params = {"top_p": 0.9, "top_k": 64, "temperature": 1.0, "topk_log_probs": 128, "logprobs": True}
    apply_greedy_sampling_params(params)
    assert params == {"top_p": 1.0, "top_k": -1, "temperature": 0, "logprobs": True}


@pytest.mark.parametrize("estimator", ["grpo", "codapo"])
@pytest.mark.parametrize("details", [[[1], [2, 3]], [[1, 2], [3, 4]]])
def test_reward_metadata_preserves_per_sample_values_through_advantage(estimator, details):
    """List-valued metadata stays one-dimensional without breaking numeric accuracy."""
    extra = _extract_reward_extra_info(
        [{"reward_extra_info": {"acc": float(i), "details": value}} for i, value in enumerate(details)]
    )
    assert extra["details"].shape == (2,)
    assert extra["details"].tolist() == details
    data = DataProto.from_dict(
        tensors={
            "token_level_rewards": torch.tensor([[0.0], [1.0]]),
            "response_mask": torch.ones(2, 1, dtype=torch.long),
            "old_log_probs": torch.full((2, 1), float(np.log(0.5))),
        },
        non_tensors={"uid": np.array(["q", "q"], dtype=object), **extra},
    )
    with patch.dict(core_algos.ADV_ESTIMATOR_REGISTRY, {"codapo": core_algos.compute_codapo_outcome_advantage}):
        result = compute_advantage_for_multi_trajectories(data, ["q_0_0", "q_1_0"], estimator)
    assert torch.isfinite(result.batch["advantages"]).all()
    assert result.batch["advantages"][0, 0] < 0 < result.batch["advantages"][1, 0]
    if estimator == "codapo":
        torch.testing.assert_close(result.batch["codapo_values"], torch.full((2,), 0.5))


class _StubTrainer(PPOTrainer):
    def on_step_end(self):
        pass

    def on_sample_end(self):
        pass


class _CustomSampler:
    def __init__(self, **kwargs):
        self.kwargs = kwargs


def _trainer_with_filter_groups(filter_groups: dict, trainer_mode: str = "sync") -> _StubTrainer:
    trainer = _StubTrainer.__new__(_StubTrainer)
    trainer.trainer_mode = trainer_mode
    trainer.config = OmegaConf.create(
        {
            "algorithm": {"filter_groups": filter_groups},
            "data": {"train_batch_size": 64, "gen_batch_size": 8},
            "reward": {"reward_model": {"enable": False, "enable_resource_pool": False}},
            "trainer": {
                "v1": {
                    trainer_mode: {},
                    "sampler": {
                        "custom_sampler": None,
                        "max_off_policy_threshold": 1,
                        "max_off_policy_strategy": "drop",
                        "sampler_kwargs": {},
                    },
                }
            },
        }
    )
    return trainer


def test_builtin_sampler_class_follows_trainer_mode():
    sync_sampler = _trainer_with_filter_groups({"enable": False}, trainer_mode="sync")._build_replay_buffer()
    async_samplers = [
        _trainer_with_filter_groups({"enable": True, "metric": "acc"}, trainer_mode=mode)._build_replay_buffer()
        for mode in ("colocate_async", "separate_async")
    ]

    assert type(sync_sampler) is ReplayBuffer
    assert all(type(sampler) is ReplayBufferAsync for sampler in async_samplers)
    assert all(sampler.filter_groups_metric == "acc" for sampler in async_samplers)
    assert all(sampler.train_batch_size is None for sampler in async_samplers)
    assert all(sampler.gen_batch_size is None for sampler in async_samplers)


def test_custom_sampler_skips_builtin_filter_groups_validation():
    trainer = _trainer_with_filter_groups({"enable": True, "metric": "acc"})
    trainer.config.trainer.v1.sampler.custom_sampler = {"path": "custom.py", "name": "CustomSampler"}

    with (
        patch("verl.trainer.ppo.v1.trainer_base.load_extern_type", return_value=_CustomSampler),
        patch.object(trainer, "_resolve_filter_groups_metric") as resolve_filter_groups_metric,
    ):
        sampler = trainer._build_replay_buffer()

    resolve_filter_groups_metric.assert_not_called()
    assert isinstance(sampler, _CustomSampler)
    assert "filter_groups_metric" not in sampler.kwargs
    assert "train_batch_size" not in sampler.kwargs
    assert "gen_batch_size" not in sampler.kwargs
    assert "max_inflight_gen_batches" not in sampler.kwargs
    assert "sync_refill_failed_groups" not in sampler.kwargs


def test_builtin_filter_groups_uses_default_inflight_limit():
    trainer = _trainer_with_filter_groups({"enable": True, "metric": "acc"})

    sampler = trainer._build_replay_buffer()

    assert sampler.filter_groups_metric == "acc"
    assert sampler.train_batch_size == 64
    assert sampler.gen_batch_size == 1
    assert sampler.max_inflight_gen_batches == 1


def test_builtin_filter_groups_forwards_configured_inflight_limit():
    trainer = _trainer_with_filter_groups({"enable": True, "metric": "acc", "max_inflight_gen_batches": 3})

    sampler = trainer._build_replay_buffer()

    assert sampler.max_inflight_gen_batches == 3


def test_builtin_sync_failure_refill_forces_single_prompt_generation():
    trainer = _trainer_with_filter_groups({"enable": False})
    trainer.config.trainer.v1.sampler.sync_refill_failed_groups = True

    sampler = trainer._build_replay_buffer()

    assert sampler.sync_refill_failed_groups is True
    assert sampler.gen_batch_size == 1


def test_sync_failure_refill_overrides_dataloader_generation_batch_size():
    trainer = _trainer_with_filter_groups({"enable": False})
    trainer.config.trainer.v1.sampler.sync_refill_failed_groups = True
    trainer.config.data.update(
        {
            "train_files": [],
            "val_files": [],
            "train_max_samples": -1,
            "val_max_samples": -1,
            "dataloader_num_workers": 0,
            "val_batch_size": 1,
            "validation_shuffle": False,
        }
    )
    trainer.config.trainer.total_epochs = 1
    trainer.config.trainer.total_training_steps = None
    trainer.parameter_sync_step = 1
    trainer.tokenizer = None
    trainer.processor = None

    with (
        patch("verl.trainer.ppo.v1.trainer_base.create_rl_dataset", side_effect=[[{}, {}], [{}]]),
        patch("verl.trainer.ppo.v1.trainer_base.create_rl_sampler", return_value=None),
        patch("verl.trainer.ppo.v1.trainer_base.StatefulDataLoader") as dataloader,
        patch("verl.trainer.ppo.v1.trainer_base.logger.warning") as warning,
    ):
        trainer._init_dataloader()

    assert trainer.config.data.gen_batch_size == 1
    assert dataloader.call_args_list[0].kwargs["batch_size"] == 1
    warning.assert_any_call("data.gen_batch_size=8 is overridden to 1.")


def test_builtin_filter_groups_warns_when_total_generation_limit_is_configured():
    trainer = _trainer_with_filter_groups({"enable": True, "metric": "acc", "max_num_gen_batches": 10})

    with patch("verl.trainer.ppo.v1.trainer_base.logger.warning") as warning:
        trainer._build_replay_buffer()

    warning.assert_called_once_with(
        "algorithm.filter_groups.max_num_gen_batches=%s is ignored by the built-in V1 ReplayBuffer; "
        "use max_inflight_gen_batches to bound concurrent Sync DAPO generation.",
        10,
    )


@pytest.mark.parametrize("score_centering", [True, False])
def test_update_actor_passes_score_centering_flag(score_centering):
    trainer = _StubTrainer.__new__(_StubTrainer)
    trainer.config = OmegaConf.create(
        {
            "actor_rollout_ref": {
                "actor": {
                    "ppo_mini_batch_size": 2,
                    "calculate_entropy": False,
                    "entropy_coeff": 0.0,
                    "ppo_epochs": 1,
                    "data_loader_seed": 1,
                    "shuffle": False,
                    "policy_loss": {"rollout_correction": {"score_centering": score_centering}},
                },
                "rollout": {"n": 4, "temperature": 1.0},
            }
        }
    )
    trainer.actor_rollout_wg = MagicMock()
    trainer.actor_rollout_wg.update_actor.return_value = {"metrics": {"mfu": 0.0}}
    batch = SimpleNamespace(extra_info={})

    trainer._update_actor(batch, {})

    assert batch.extra_info["score_centering"] is score_centering


def test_codapo_builds_focused_batch_with_fresh_independent_uids():
    trainer = _StubTrainer.__new__(_StubTrainer)
    trainer.config = OmegaConf.create({"algorithm": {"codapo_top_k": 2}})
    prompt_batch = tu.get_tensordict(
        {
            "uid": np.array(["q0", "q1", "q2", "q3"], dtype=object),
            "row": torch.arange(4),
        }
    )
    rollout_data = tu.get_tensordict(
        {
            "uid": np.repeat(np.array(["q0", "q1", "q2", "q3"], dtype=object), 2),
            "codapo_values": torch.tensor([0.1, 0.1, 0.9, 0.9, 0.8, 0.8, 0.2, 0.2]),
        }
    )
    rollout_batch = KVBatchMeta(partition_id="train", keys=[f"key-{row}" for row in range(8)], tags=[{}] * 8)
    with patch("verl.trainer.ppo.v1.trainer_base.tq.kv_batch_get", return_value=rollout_data):
        focused_batch = trainer._build_codapo_resampled_batch(prompt_batch, rollout_batch, {})

    focused_uids = [tu.unwrap_non_tensor_data(uid) for uid in focused_batch["uid"]]
    assert focused_batch["row"].tolist() == [1, 2, 1, 2]
    assert len(set(focused_uids)) == 4
    assert set(focused_uids).isdisjoint({"q0", "q1", "q2", "q3"})


def test_codapo_step_uses_pending_focused_batch_before_fetching_new_prompts():
    trainer = _StubTrainer.__new__(_StubTrainer)
    trainer.config = OmegaConf.create({"data": {"train_batch_size": 2}})
    trainer.parameter_sync_step = 1
    trainer._codapo_enabled = True
    trainer._codapo_resampled_batch = None
    trainer.global_steps = 8  # Phase is state-driven, not tied to step parity.
    original_batch = tu.get_tensordict({"uid": np.array(["q0", "q1"], dtype=object)})
    focused_batch = tu.get_tensordict({"uid": np.array(["f0", "f1"], dtype=object)})
    rollout_batch = KVBatchMeta(partition_id="train", keys=["k0", "k1"], tags=[{}, {}])

    with (
        patch.object(trainer, "_next_train_batch", return_value=original_batch) as fetch,
        patch.object(trainer, "_submit_batch_to_rollout") as submit,
        patch.object(trainer, "_step_once", return_value=rollout_batch),
        patch.object(trainer, "_build_codapo_resampled_batch", return_value=focused_batch),
    ):
        trainer.step({}, {})
        trainer.global_steps += 1
        trainer.step({}, {})

    fetch.assert_called_once_with()
    assert [call.args[0] for call in submit.call_args_list] == [original_batch, focused_batch]
    assert trainer._codapo_resampled_batch is None
