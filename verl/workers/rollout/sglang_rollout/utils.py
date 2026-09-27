# Copyright 2023-2024 SGLang Team
# Copyright 2025 ModelBest Inc. and/or its affiliates
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

import pickle
from typing import Any, Iterator, Optional

import numpy as np
import torch
import torch.distributed as dist

from verl.utils.device import get_device_capability, get_device_name
from verl.workers.rollout.utils import ensure_async_iterator

SGLANG_LORA_NAME = "verl_actor_lora_name"

_DEEPSEEK_V4_FUSION_MEMBERS = (
    ("wq_a.weight", "wkv.weight"),
    ("wq_a.scale", "wkv.scale"),
    ("wq_a.weight_scale_inv", "wkv.weight_scale_inv"),
    ("compressor.wkv.weight", "compressor.wgate.weight"),
    ("indexer.compressor.wkv.weight", "indexer.compressor.wgate.weight"),
)
DEEPSEEK_V4_FUSION_GROUPS = tuple(
    tuple(f".{attention}.{member}" for member in members)
    for attention in ("self_attn", "attn")
    for members in _DEEPSEEK_V4_FUSION_MEMBERS
)


def _fusion_key(name: str, groups: tuple[tuple[str, ...], ...]):
    matches = [
        (index, suffix, len(group)) for index, group in enumerate(groups) for suffix in group if name.endswith(suffix)
    ]
    if len(matches) > 1:
        raise ValueError(f"{name!r} matches multiple fusion groups: {matches}")
    if not matches:
        return None
    index, suffix, size = matches[0]
    return name[: -len(suffix)], index, size


def normalize_peft_config_for_sglang(peft_config: dict) -> dict:
    """Normalize an engine's adapter config (enums to strings) for SGLang's adapter loader."""
    normalized = dict(peft_config)
    for key in ("task_type", "peft_type"):
        if key in normalized:
            normalized[key] = getattr(normalized[key], "value", normalized[key])
    if "peft_type" not in normalized:
        raise ValueError(
            "adapter config has no 'peft_type', which SGLang's adapter loader requires. See "
            "BaseEngine.get_per_tensor_param for the keys. Keys present: " + ", ".join(sorted(normalized))
        )
    # A bare string must stay one: list() would tear "all-linear" into characters.
    target_modules = normalized["target_modules"]
    normalized["target_modules"] = target_modules if isinstance(target_modules, str) else list(target_modules)
    return normalized


def lora_rank_of(model_config) -> int:
    """The LoRA rank, from whichever block carries it: megatron sets ``model.lora.rank``, fsdp
    the flat ``model.lora_rank``."""
    return max(int(getattr(model_config, "lora_rank", 0) or 0), int(model_config.lora.get("rank", 0) or 0))


def lora_served_as_adapter(model_config) -> bool:
    """Whether SGLang should serve LoRA as a hot-swappable adapter.

    ``HFModelConfig`` carries two LoRA config blocks that are never synced: megatron
    runs set ``model.lora.rank`` (dict) while fsdp runs set the flat ``model.lora_rank``,
    so both must be checked to detect that LoRA is enabled at all.

    With ``model.lora.merge=True`` the trainer merges the adapter into the base weights
    and pushes a full HF-keyed weight update (``peft_config=None``), so no adapter is ever
    loaded into SGLang: the engine must not be launched with ``enable_lora`` and requests
    must not carry a ``lora_path``.
    """
    lora_enabled = lora_rank_of(model_config) > 0
    return lora_enabled and not model_config.lora.get("merge", False)


def lora_base_kept_on_sleep(model_config) -> bool:
    """Whether sleep keeps the base weights on GPU and releases only the kv_cache.

    True in adapter mode (see :func:`lora_served_as_adapter`), where the trainer pushes only
    the adapter after the first sync. With ``model.lora.resync_base=True`` the trainer re-syncs
    the base before the adapter on every update, so sleep releases the weights too.
    """
    return lora_served_as_adapter(model_config) and not model_config.lora.get("resync_base", False)


def sglang_lora_target_modules(target_modules: Any) -> list[str]:
    """Render verl's ``model.target_modules`` as SGLang's ``lora_target_modules``."""
    if target_modules == "all-linear":
        return ["all"]
    if isinstance(target_modules, str):
        raise ValueError(
            f"SGLang cannot serve a regex `target_modules` ({target_modules!r}); PEFT matches it "
            f"against the whole parameter key. Use `all-linear`, or list the module names."
        )
    return list(target_modules)


def default_moe_runner_backend(quantization: Optional[str], engine_kwargs: Any, hf_config: Any = None) -> Optional[str]:
    """MoE runner verl asks SGLang for when the user leaves it to ``auto``; None keeps SGLang's choice.

    On Blackwell (compute capability 10.x) SGLang resolves ``moe_runner_backend="auto"`` to ``flashinfer_trtllm``
    for unquantized Qwen3-MoE- and DeepSeek-family checkpoints when no ``moe_a2a_backend`` is set. That runner keeps
    bf16 expert weights in a block layout, and ``update_weights_from_tensor`` restores the load-time shape only for
    ``flashinfer_trtllm_routed``, so the first weight sync fails in ``FusedMoE._load_w13`` and the scheduler exits
    (sgl-project/sglang#27787, still in sglang 0.5.21). Under the same conditions verl asks for the Triton runner,
    which SGLang's unquantized MoE method falls back to everywhere else and which takes weight updates. A quantized
    rollout or checkpoint uses SGLang's quantized MoE methods instead and is left alone.
    """
    if engine_kwargs.get("moe_runner_backend") not in (None, "auto"):
        return None  # the user picked a runner
    if engine_kwargs.get("moe_a2a_backend") not in (None, "none"):
        return None  # with an a2a backend SGLang does not pick flashinfer_trtllm
    if quantization is not None or getattr(hf_config, "quantization_config", None) is not None:
        return None  # quantized rollout or checkpoint: not the bf16 path
    if torch.version.hip is not None:
        return None
    major, _ = get_device_capability()
    return "triton" if major == 10 else None


def broadcast_pyobj(
    data: list[Any],
    rank: int,
    dist_group: Optional[torch.distributed.ProcessGroup] = None,
    src: int = 0,
    force_cpu_device: bool = False,
):
    """from https://github.com/sgl-project/sglang/blob/844e2f227ab0cce6ef818a719170ce37b9eb1e1b/python/sglang/srt/utils.py#L905

    Broadcast inputs from src rank to all other ranks with torch.dist backend.
    The `rank` here refer to the source rank on global process group (regardless
    of dist_group argument).
    """
    device = torch.device(get_device_name() if not force_cpu_device else "cpu")

    if rank == src:
        if len(data) == 0:
            tensor_size = torch.tensor([0], dtype=torch.long, device=device)
            dist.broadcast(tensor_size, src=src, group=dist_group)
        else:
            serialized_data = pickle.dumps(data)
            size = len(serialized_data)

            tensor_data = torch.ByteTensor(np.frombuffer(serialized_data, dtype=np.uint8)).to(device)
            tensor_size = torch.tensor([size], dtype=torch.long, device=device)

            dist.broadcast(tensor_size, src=src, group=dist_group)
            dist.broadcast(tensor_data, src=src, group=dist_group)
        return data
    else:
        tensor_size = torch.tensor([0], dtype=torch.long, device=device)
        dist.broadcast(tensor_size, src=src, group=dist_group)
        size = tensor_size.item()

        if size == 0:
            return []

        tensor_data = torch.empty(size, dtype=torch.uint8, device=device)
        dist.broadcast(tensor_data, src=src, group=dist_group)

        serialized_data = bytes(tensor_data.cpu().numpy())
        data = pickle.loads(serialized_data)
        return data


def _compact_for_bucket(tensor: torch.Tensor) -> torch.Tensor:
    """Return a tensor safe to retain in a weight-sync bucket without pinning extra memory.

    ``get_named_tensor_buckets`` keeps every tensor alive until its bucket is flushed. A tensor
    that is a *view* into a larger backing buffer would therefore keep that whole buffer resident
    (and ship the whole buffer downstream), so such views must be compacted with ``clone()``.

    However the weights synced here come from ``DTensor.full_tensor()`` (a fresh all-gather) and
    already own tight, contiguous storage. Cloning those allocates a second full-size buffer and
    transiently doubles the tensor's footprint -- which OOMs on multi-GiB fused MoE weights
    (e.g. ``[num_experts, ...]`` ``gate_up_proj``/``qkv``) while the actor params and rollout
    weights are both already resident. Skip the clone when the tensor already owns its storage.
    """
    return tensor.clone() if tensor._base is not None else tensor


async def get_named_tensor_buckets(
    iterable: Iterator[tuple[str, torch.Tensor]],
    bucket_bytes: int,
    fusion_groups: tuple[tuple[str, ...], ...] = (),
) -> Iterator[list[tuple[str, torch.Tensor]]]:
    """
    Group tensors into buckets based on a specified size in megabytes.

    Args:
        iterable: An iterator of tuples containing tensor names and tensors.
        bucket_bytes: The maximum size of each bucket in bytes.

    Yields:
        Lists of tuples, where each tuple contains a tensor name and its corresponding tensor.

    Example:
        >>> tensors = [('tensor1', torch.randn(1000, 1000)), ('tensor2', torch.randn(2000, 2000))]
        >>> for bucket in get_named_tensor_buckets(tensors, bucket_size_mb=10):
        ...     print(bucket)
        [('tensor1', tensor(...)), ('tensor2', tensor(...))]

    """
    if bucket_bytes <= 0:
        raise ValueError(f"bucket_bytes must be greater than 0, got {bucket_bytes}")

    current_bucket = []
    current_size = 0
    # Members of a fused destination param (SGLang's DSv4 wqkv_a / wkv_gate) are
    # held here until the group is whole, then placed in one bucket: that loader
    # cats both halves inside a single load_weights call and asserts its cache
    # empty on return, so a bucket boundary between them makes it fire. A full
    # sync contains every member by construction, so this only ever delays a
    # tensor by its sibling -- nothing is dropped.
    staged: dict = {}

    def _place(entries):
        """Put an indivisible run of entries in a bucket, cutting before it if
        it would not fit rather than partway through."""
        nonlocal current_bucket, current_size
        total = sum(sz for _, _, sz in entries)
        if current_bucket and current_size + total > bucket_bytes:
            out, current_bucket, current_size = current_bucket, [], 0
            return out, entries
        return None, entries

    async for name, tensor in ensure_async_iterator(iterable):
        tensor_size = tensor.element_size() * tensor.numel()
        match = _fusion_key(name, fusion_groups)
        if match is not None:
            prefix, group_index, expected_size = match
            key = (prefix, group_index)
            slot = staged.setdefault(key, [])
            slot.append((name, _compact_for_bucket(tensor), tensor_size))
            if len(slot) < expected_size:
                continue
            entries = staged.pop(key)
        else:
            entries = [(name, _compact_for_bucket(tensor), tensor_size)]

        flushed, entries = _place(entries)
        if flushed:
            yield flushed
        for n, t, sz in entries:
            current_bucket.append((n, t))
            current_size += sz

    if staged:
        raise ValueError(f"fused parameter groups never completed in this sync: {sorted(staged)}")
    if current_bucket:
        yield current_bucket
