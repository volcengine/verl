# Copyright 2026 Bytedance Ltd. and/or its affiliates
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

"""BF16 transport checks for native NVFP4 refit."""

import pytest
import torch

from verl.utils.real_nvfp4.vllm_runtime import RealNVFP4BF16TransportCheck


def _weights():
    return [
        (f"model.layers.{layer}.mlp.experts.{expert}.{projection}.weight", torch.ones(2, 16))
        for layer in range(2)
        for expert in range(2)
        for projection in ("gate_proj", "up_proj", "down_proj")
    ]


def _attest(weights):
    check = RealNVFP4BF16TransportCheck({"num_hidden_layers": 2, "num_experts": 2})
    # Split the round into two buckets, as the receiver delivers it.
    check.check_bucket(weights[: len(weights) // 2])
    check.check_bucket(weights[len(weights) // 2 :])
    check.finish()


def test_expert_coverage_accepts_complete_reordered_stream():
    weights = list(reversed(_weights()))
    weights.insert(0, ("model.embed_tokens.weight", torch.ones(2, 16)))
    _attest(weights)


def test_expert_coverage_rejects_missing_projection():
    with pytest.raises(RuntimeError, match="missing 1 expert weights"):
        _attest(_weights()[:-1])
