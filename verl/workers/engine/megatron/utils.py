# Copyright 2025 Bytedance Ltd. and/or its affiliates
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


from verl.utils.device import get_torch_device, is_device_available


def set_random_seed(seed):
    import random

    import numpy as np
    import torch

    torch.manual_seed(seed)
    np.random.seed(seed)
    random.seed(seed)
    # model_parallel_cuda_manual_seed() seeds Megatron-Core's CUDA RNG tracker. This is
    # required for Megatron model construction: layers such as VocabParallelEmbedding call
    # get_cuda_rng_tracker().fork() and raise "cuda rng state model-parallel-rng is not
    # added" if the tracker was never seeded. On Ascend/NPU torch has no CUDA backend, but
    # torch_npu/MindSpeed patch Megatron's tracker so this call works there as well. Only
    # skip it when no real accelerator (CUDA or NPU) is present, which avoids "Torch not
    # compiled with CUDA enabled" on CPU-only environments.
    if is_device_available and get_torch_device().device_count() > 0:
        from megatron.core import tensor_parallel

        tensor_parallel.model_parallel_cuda_manual_seed(seed)
    # FIXME: torch cumsum not support deterministic (used in vllm sampler),
    # https://github.com/pytorch/pytorch/issues/89492
    # torch.use_deterministic_algorithms(True, warn_only=True)
    # os.environ['CUBLAS_WORKSPACE_CONFIG'] = ':4096:8'
