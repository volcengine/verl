# Copyright 2023-2024 SGLang Team
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
import asyncio
import json
import logging
import os
import secrets
from pathlib import Path
from typing import Any, Optional

import ray
import sglang
import sglang.srt.entrypoints.engine
import torch
from packaging import version
from ray.actor import ActorHandle
from sglang.srt.entrypoints.http_server import (
    Engine,
    ServerArgs,
    _GlobalState,
    app,
    set_global_state,
)
from sglang.srt.managers.io_struct import (
    ContinueGenerationReqInput,
    GenerateReqInput,
    PauseGenerationReqInput,
    ReleaseMemoryOccupationReqInput,
    ResumeMemoryOccupationReqInput,
)
from sglang.srt.managers.tokenizer_manager import ServerStatus

from verl.plugin.platform import get_platform
from verl.utils.config import omega_conf_to_dataclass
from verl.utils.device import get_visible_devices_keyword
from verl.utils.net_utils import get_free_port, is_valid_ipv6_address
from verl.utils.profiler import (
    build_rollout_dist_profiler,
    build_sglang_profiler_args,
    relocate_rollout_traces,
    rollout_profiler_global_ranks,
)
from verl.utils.tracking import RLInsightLogger
from verl.workers.config import HFModelConfig, RolloutConfig
from verl.workers.rollout.replica import RolloutMode, RolloutReplica, TokenOutput
from verl.workers.rollout.sglang_rollout.sglang_rollout import _set_envs_and_config
from verl.workers.rollout.sglang_rollout.utils import (
    SGLANG_LORA_NAME,
    lora_rank_of,
    lora_served_as_adapter,
    sglang_lora_target_modules,
)
from verl.workers.rollout.utils import get_max_position_embeddings, run_uvicorn

logger = logging.getLogger(__file__)
logger.setLevel(logging.INFO)

visible_devices_keyword = get_visible_devices_keyword()


def _extract_prompt_logprobs_sglang(
    meta_info: dict,
    num_prompt_logprobs: int,
    sequence_length: int,
    result_dict: dict[str, list],
) -> None:
    """Shape SGLang input-logprobs into the vLLM ``extract_prompt_logprobs`` contract.
    Populates ``result_dict`` with two ``[sequence_length, max(num_prompt_logprobs, 1)]``
    lists — ``prompt_ids`` and ``prompt_logprobs`` — so the distillation teacher
    consumer in ``teacher_manager.AsyncTeacherLLMServerManager`` can treat vLLM and
    SGLang teachers interchangeably.
    SGLang returns input logprobs with length ``S == len(input_ids)`` whose first
    entry has ``logprob=None`` (no predicting context). That matches the vLLM
    convention, so we skip entry 0 and append a trailing dummy row to keep the
    total length equal to the consumer's ``len(sequence_ids)`` assertion.
    """
    input_token_logprobs = meta_info.get("input_token_logprobs") or []
    if num_prompt_logprobs > 0:
        input_top_logprobs = meta_info.get("input_top_logprobs") or []
    prompt_ids_ls: list[list[int]] = []
    prompt_logprobs_ls: list[list[float]] = []
    # Entry 0 has logprob=None (no predicting context); skip it, matching vLLM.
    for position in range(1, len(input_token_logprobs)):
        if num_prompt_logprobs == 0:
            logprob, token_id, _ = input_token_logprobs[position]
            prompt_ids_ls.append([int(token_id)])
            prompt_logprobs_ls.append([float(logprob)])
        else:
            top_entries = input_top_logprobs[position]
            # SGLang returns ranked best-first; we preserve that ordering so rank
            # 0 is the top-1 token, matching the vLLM extractor's rank-1 slot.
            ids = [int(tok_id) for _, tok_id, _ in top_entries]
            logprobs = [float(logprob) for logprob, _, _ in top_entries]
            assert len(ids) == num_prompt_logprobs, (
                f"SGLang returned {len(ids)} top logprobs at position {position}, expected {num_prompt_logprobs}."
            )
            prompt_ids_ls.append(ids)
            prompt_logprobs_ls.append(logprobs)
    # Trailing dummy row so total length == len(sequence_ids), matching vLLM.
    pad_width = max(num_prompt_logprobs, 1)
    prompt_ids_ls.append([0] * pad_width)
    prompt_logprobs_ls.append([0.0] * pad_width)
    assert len(prompt_ids_ls) == sequence_length, (
        f"SGLang prompt_logprobs length ({len(prompt_ids_ls)}) does not match "
        f"sequence length ({sequence_length}); check logprob_start_len=0 invariant."
    )
    result_dict["prompt_ids"] = prompt_ids_ls
    result_dict["prompt_logprobs"] = prompt_logprobs_ls


class SGLangHttpServer:
    """SGLang http server in single node, this is equivalent to launch server with command line:
    ```
    python -m sglang.launch_server --node-rank 0 --nnode 1 ...
    ```

    Args:
        config (DictConfig): full config.
        rollout_mode (RolloutMode): rollout mode.
        replica_rank (int): replica rank, a replica may contain multiple nodes.
        node_rank (int): node rank.
        nnodes (int): number of nodes.
        cuda_visible_devices (str): cuda visible devices.
    """

    def __init__(
        self,
        config: RolloutConfig,
        model_config: HFModelConfig,
        rollout_mode: RolloutMode,
        workers: list[ActorHandle],
        replica_rank: int,
        node_rank: int,
        nnodes: int,
        cuda_visible_devices: str,
        base_gpu_id: int,
        disaggregation_role: str = "null",
        disaggregation_bootstrap_port: Optional[int] = None,
    ):
        print(
            f"SGLang http server: {rollout_mode=}, {replica_rank=}, {node_rank=}, "
            f"{nnodes=}, {cuda_visible_devices=}, role={disaggregation_role}"
        )
        os.environ[visible_devices_keyword] = cuda_visible_devices

        assert disaggregation_role in ("null", "prefill", "decode"), (
            f"disaggregation_role must be 'null'|'prefill'|'decode', got {disaggregation_role!r}"
        )
        self._disaggregation_role = disaggregation_role
        self._disaggregation_bootstrap_port = disaggregation_bootstrap_port

        self.config: RolloutConfig = omega_conf_to_dataclass(config)
        self.model_config: HFModelConfig = omega_conf_to_dataclass(model_config, dataclass_type=HFModelConfig)
        max_position_embeddings = get_max_position_embeddings(self.model_config.hf_config)
        if self.config.max_model_len is None:
            self.config.max_model_len = max_position_embeddings
        else:
            if self.config.max_model_len > max_position_embeddings:
                raise ValueError(
                    f"max_model_len ({self.config.max_model_len}) should be less than or equal to "
                    f"max_position_embeddings ({max_position_embeddings})"
                )
        self.rollout_mode = rollout_mode
        self.workers = workers

        self.replica_rank = replica_rank
        self.node_rank = node_rank
        self.nnodes = nnodes
        self.base_gpu_id = base_gpu_id
        # model weights version, set by ServerAdapter when update weights.
        self.global_steps = None

        # PD peer linkage populated post-launch by SGLangPDReplica.set_pd_peer.
        self._pd_decode_peers: list[ActorHandle] = []
        self._pd_bootstrap_host: Optional[str] = None

        # used for http server
        self._server_address = ray.util.get_node_ip_address().strip("[]")
        self._server_port = None

        # used for controlling sglang server profiler
        profiler_config = self.config.profiler
        tool_config = None
        if profiler_config is not None:
            if profiler_config.tool in ["torch", "npu"]:
                tool_config = omega_conf_to_dataclass((profiler_config.tool_config or {}).get(profiler_config.tool))
            else:
                logger.warning(f"agent loop only support torch and npu profiler, got {profiler_config.tool}")
                profiler_config = None
        # `ranks` in the rollout profiler config are global GPU ranks (as in the training roles);
        # map them to the replica that owns them so e.g. ranks=[0, 8] with tp=8 profiles the replicas
        # holding global ranks 0 and 8 (replicas 0 and 1), not replica indices 0 and 8.
        self.replica_world_size = (
            self.config.tensor_model_parallel_size
            * self.config.data_parallel_size
            * self.config.pipeline_model_parallel_size
        )
        self.profiler_controller = build_rollout_dist_profiler(
            self.replica_rank, self.replica_world_size, config=profiler_config, tool_config=tool_config
        )
        # A tp>1 engine profiles its whole replica, but the user asked for specific global GPU ranks;
        # keep only those when relocating so ranks=[0, 8] yields exactly GPU 0 and 8, not their tp-mates.
        self.profiler_keep_global_ranks = rollout_profiler_global_ranks(profiler_config)

        # For multi-node, we need dist_init_addr so nodes can coordinate NCCL init.
        # For single-node, let SGLang handle port selection internally via nccl_port,
        # which also avoids port conflicts.
        self._master_address = None
        self._master_port = None
        self._master_sock = None
        if self.nnodes > 1 and self.node_rank == 0:
            self._master_address = self._server_address
            self._master_port, self._master_sock = get_free_port(self._server_address, with_alive_sock=True)
            logger.info(
                f"SGLangHttpServer, replica_rank: {self.replica_rank}, "
                f"master address: {self._master_address}, port: {self._master_port}"
            )

    def get_master_address(self):
        """Get master address and port for init NCCL process group."""
        return self._master_address, self._master_port

    def get_server_address(self):
        """Get http server address and port."""
        assert self._server_port is not None, "http server is not launched, port is None"
        return self._server_address, self._server_port

    async def set_pd_peer(self, decode_peers: list, bootstrap_host: str):
        assert isinstance(decode_peers, list) and decode_peers
        self._pd_decode_peers = list(decode_peers)
        self._pd_bootstrap_host = bootstrap_host

    def _prepend_cu12_lib_to_ld_library_path(self) -> None:
        """Ray runtime_env.pip installs cu12 into a transient venv, not the usual
        site-packages. NIXL's UCX plugin dlopens libcudart.so.12 from
        LD_LIBRARY_PATH; wrong path ⇒ scheduler subprocess dies with SIGABRT."""
        try:
            import nvidia.cuda_runtime as cu12_mod
        except ImportError as e:
            logger.warning(
                f"nvidia.cuda_runtime not importable: {e}. "
                f"NIXL may fail with 'libcudart.so.12: cannot open shared object'."
            )
            return
        cu12_lib = str(Path(cu12_mod.__file__).parent / "lib")
        if not os.path.isdir(cu12_lib):
            return
        existing = os.environ.get("LD_LIBRARY_PATH", "")
        if cu12_lib in existing.split(":"):
            return
        os.environ["LD_LIBRARY_PATH"] = f"{cu12_lib}:{existing}" if existing else cu12_lib
        logger.info(f"Prepended {cu12_lib} to LD_LIBRARY_PATH for NIXL/UCX dlopen.")

    async def launch_server(self, master_address: str = None, master_port: int = None):
        if self._disaggregation_role != "null":
            self._prepend_cu12_lib_to_ld_library_path()

        if self.nnodes > 1:
            if self.node_rank != 0:
                assert master_address and master_port, "non-master node should provide master address and port"
                self._master_address = master_address
                self._master_port = master_port

        engine_kwargs = self.config.get("engine_kwargs", {}).get("sglang", {}) or {}
        attention_backend = engine_kwargs.pop("attention_backend", None)
        mm_attention_backend = engine_kwargs.pop("mm_attention_backend", None)
        # Delta checkpoint engines apply sparse weight updates in place through SGLang's
        # custom-weight-loader hook; register the verl loader so the update requests'
        # load_format resolves inside the TP workers.
        custom_weight_loader = list(engine_kwargs.pop("custom_weight_loader", None) or [])
        ce_backend = str((self.config.get("checkpoint_engine", None) or {}).get("backend", ""))
        if ce_backend == "delta_sharded":
            from verl.workers.rollout.sglang_rollout.delta_loader import LOADER_FQN

            if LOADER_FQN not in custom_weight_loader:
                custom_weight_loader.append(LOADER_FQN)
        if attention_backend is None:
            if torch.version.hip is not None:
                attention_backend = "aiter"
            elif version.parse(sglang.__version__) >= version.parse("0.5.12"):
                # FA3 CUDA-graph capture is broken on sglang>=0.5.12 (#22800);
                # default to flashinfer (users can opt into fa4 via engine_kwargs).
                attention_backend = "flashinfer"
            else:
                attention_backend = "fa3"
        # mm_attention_backend uses a different name space than attention_backend
        # (e.g. text "flashinfer" vs vision "flashinfer_cudnn"), so don't mirror it.
        # Leave None to let sglang's VisionAttention auto-pick per device
        # (triton_attn on Ada, fa3 on Hopper, fa4 on Blackwell).
        quantization = self.config.get("quantization", None)
        if quantization is not None:
            if quantization == "fp8":
                from verl.utils.sglang.sglang_fp8_utils import build_sglang_fp8_quant_config

                fp8_block_quant_kwargs = build_sglang_fp8_quant_config(self.model_config.hf_config)
            else:
                raise ValueError(f"Currently only support fp8 quantization, got: {quantization}")
        infer_tp = self.config.tensor_model_parallel_size * self.config.data_parallel_size
        args = {
            "model_path": self.model_config.local_path,
            "dtype": self.config.dtype,
            "mem_fraction_static": self.config.gpu_memory_utilization,
            "disable_cuda_graph": self.config.enforce_eager,
            "enable_memory_saver": True,
            "base_gpu_id": self.base_gpu_id,
            "gpu_id_step": 1,
            "tp_size": infer_tp,
            "dp_size": self.config.data_parallel_size,
            "ep_size": self.config.expert_parallel_size,
            "node_rank": self.node_rank,
            "load_format": self.config.load_format,
            "nnodes": self.nnodes,
            "trust_remote_code": self.model_config.trust_remote_code,
            "max_running_requests": self.config.get("max_num_seqs", None),
            "log_level": "error",
            "mm_attention_backend": mm_attention_backend,
            "attention_backend": attention_backend,
            "skip_tokenizer_init": self.config.skip_tokenizer_init,
            "skip_server_warmup": True,
            "quantization": quantization,
            "json_model_override_args": json.dumps({"quantization_config": fp8_block_quant_kwargs})
            if quantization == "fp8"
            else json.dumps({}),
            "custom_weight_loader": custom_weight_loader or None,
            **engine_kwargs,
        }

        # update lora-related args
        if self.lora_as_adapter:
            args.update(
                {
                    "enable_lora": True,
                    "max_lora_rank": lora_rank_of(self.model_config),
                    "lora_target_modules": sglang_lora_target_modules(self.model_config.target_modules),
                }
            )
        # Only set dist_init_addr for multi-node; for single-node, let SGLang
        # handle port selection internally via nccl_port to avoid conflicts.
        if self.nnodes > 1:
            dist_init_addr = (
                f"[{self._master_address}]:{self._master_port}"
                if is_valid_ipv6_address(self._master_address)
                else f"{self._master_address}:{self._master_port}"
            )
            args["dist_init_addr"] = dist_init_addr

        if self.config.prometheus.enable or RLInsightLogger.enabled():
            if self.config.prometheus.served_model_name:
                # Extract model name from path if it's a full path
                served_model_name = self.config.prometheus.served_model_name
                if "/" in served_model_name:
                    # If it's a full path, extract the last part as model name
                    served_model_name = served_model_name.split("/")[-1]
                args["served_model_name"] = served_model_name

            # start sglang metrics
            args["enable_metrics"] = True

        # HYBRID mode also needs CPU weight backup so that:
        #   1. sleep() can release GPU weights to free memory for the training engine.
        #   2. naive update_weights() can call resume(tags=["weights"]) to reload weights
        #      from CPU before applying the latest trainer weights via IPC.
        # Without this, sleep() releases GPU memory but update_weights() cannot restore
        # the weight buffers, causing OOM when training tries to use the freed memory.
        args["enable_weights_cpu_backup"] = (
            self.rollout_mode in (RolloutMode.COLOCATED, RolloutMode.HYBRID) or self.model_config.lora_rank > 0
        )

        if self._disaggregation_role != "null":
            disagg = self.config.disaggregation
            args["disaggregation_mode"] = self._disaggregation_role
            args["disaggregation_transfer_backend"] = disagg.transfer_backend
            # Bind HTTP + bootstrap to the routable node IP; default 127.0.0.1
            # makes decode-to-prefill bootstrap connection fail across nodes.
            args["host"] = self._server_address
            if self._disaggregation_bootstrap_port is not None:
                args["disaggregation_bootstrap_port"] = self._disaggregation_bootstrap_port
            if disagg.decode_tensor_model_parallel_size is not None:
                args["disaggregation_decode_tp"] = disagg.decode_tensor_model_parallel_size
            if disagg.ib_device is not None:
                args["disaggregation_ib_device"] = disagg.ib_device

        if self.config.enable_rollout_routing_replay:
            args.update({"enable_return_routed_experts": True})

        # mtp
        if self.config.mtp is not None and self.config.mtp.enable and self.config.mtp.enable_rollout:
            args["speculative_algorithm"] = self.config.mtp.speculative_algorithm
            args["speculative_num_steps"] = self.config.mtp.speculative_num_steps
            args["speculative_eagle_topk"] = self.config.mtp.speculative_eagle_topk
            args["speculative_num_draft_tokens"] = self.config.mtp.speculative_num_draft_tokens

            args["enable_weights_cpu_backup"] = True
            args["enable_draft_weights_cpu_backup"] = True

        # NOTE: We can't directly call SGLang's launch_server since it's not an async function.
        # https://github.com/sgl-project/sglang/blob/main/python/sglang/srt/entrypoints/http_server.py
        sglang.srt.entrypoints.engine._set_envs_and_config = _set_envs_and_config
        os.environ["SGLANG_BLOCK_NONZERO_RANK_CHILDREN"] = "0"
        server_args = ServerArgs(**args)
        self.tokenizer_manager, self.template_manager, self.scheduler_info, *_ = Engine._launch_subprocesses(
            server_args=server_args,
            init_tokenizer_manager_func=sglang.srt.entrypoints.engine.init_tokenizer_manager,
            run_scheduler_process_func=sglang.srt.entrypoints.engine.run_scheduler_process,
            run_detokenizer_process_func=sglang.srt.entrypoints.engine.run_detokenizer_process,
        )

        # In multi-node cases, non-zero rank nodes should not launch http server.
        if self.node_rank > 0:
            return

        set_global_state(
            _GlobalState(
                tokenizer_manager=self.tokenizer_manager,
                template_manager=self.template_manager,
                scheduler_info=self.scheduler_info,
            )
        )
        app.is_single_tokenizer_mode = True

        # Set warmup_thread_{kw}args to avoid AttributeError in lifespan function
        app.server_args = server_args
        app.warmup_thread_kwargs = {"server_args": server_args}
        app.warmup_thread_args = (server_args, None, None)

        # Manually add Prometheus middleware before starting server
        # This ensures /metrics endpoint is available immediately
        if server_args.enable_metrics:
            from sglang.srt.utils.common import add_prometheus_middleware

            add_prometheus_middleware(app)

        self._server_port, self._server_task = await run_uvicorn(app, server_args, self._server_address)
        self.tokenizer_manager.server_status = ServerStatus.Up

    async def wake_up(self):
        if self.node_rank != 0:
            return

        if self.rollout_mode == RolloutMode.HYBRID:
            # In hybrid mode, rollout is wake up in `update_weights`
            raise ValueError(f"wake_up not support rollout_mode {self.rollout_mode}")
        elif self.rollout_mode == RolloutMode.COLOCATED:
            # Resume exactly what sleep() released; adapter mode keeps the base weights resident.
            tags = ["kv_cache"] if self.lora_as_adapter else ["kv_cache", "weights"]
            obj = ResumeMemoryOccupationReqInput(tags=tags)
            await self.tokenizer_manager.resume_memory_occupation(obj, None)
            await self.tokenizer_manager.flush_cache()
        elif self.rollout_mode == RolloutMode.STANDALONE:
            # In standalone mode, resume kv_cache if free_cache_engine is enabled
            obj = ResumeMemoryOccupationReqInput(tags=["kv_cache"])
            await self.tokenizer_manager.resume_memory_occupation(obj, None)
            await self.tokenizer_manager.flush_cache()

    @property
    def lora_as_adapter(self) -> bool:
        """See :func:`verl.workers.rollout.sglang_rollout.utils.lora_served_as_adapter`."""
        return lora_served_as_adapter(self.model_config)

    async def sleep(self):
        if self.node_rank != 0 or not self.config.free_cache_engine:
            return

        # When using LoRA as adapter (merge=False), only release kv_cache —
        # keep base weights in GPU so we only need to sync adapter deltas.
        # Mirrors the vLLM sleep() pattern in vllm_async_server.py.
        if self.lora_as_adapter:
            tags = ["kv_cache"]
        else:
            tags = ["kv_cache", "weights"]

        if self.rollout_mode == RolloutMode.HYBRID:
            obj = ReleaseMemoryOccupationReqInput(tags=tags)
            await self.tokenizer_manager.release_memory_occupation(obj, None)
        elif self.rollout_mode == RolloutMode.COLOCATED:
            obj = ReleaseMemoryOccupationReqInput(tags=tags)
            await self.tokenizer_manager.release_memory_occupation(obj, None)
        elif self.rollout_mode == RolloutMode.STANDALONE:
            # In standalone mode, resume kv_cache if free_cache_engine is enabled
            obj = ReleaseMemoryOccupationReqInput(tags=["kv_cache"])
            await self.tokenizer_manager.release_memory_occupation(obj, None)

    async def clear_kv_cache(self):
        if self.node_rank == 0:
            await self.tokenizer_manager.flush_cache()

    async def release_kv_cache(self):
        """Release only kv_cache GPU memory, keeping model weights intact."""
        if self.node_rank != 0 or not self.config.free_cache_engine:
            return
        obj = ReleaseMemoryOccupationReqInput(tags=["kv_cache"])
        await self.tokenizer_manager.release_memory_occupation(obj, None)

    async def resume_kv_cache(self):
        """Restore kv_cache GPU memory after a weight sync. Counterpart to release_kv_cache()."""
        if self.node_rank != 0 or not self.config.free_cache_engine:
            return
        obj = ResumeMemoryOccupationReqInput(tags=["kv_cache"])
        await self.tokenizer_manager.resume_memory_occupation(obj, None)
        await self.tokenizer_manager.flush_cache()

    async def generate(
        self,
        prompt_ids: torch.Tensor,
        sampling_params: dict[str, Any],
        request_id: str,
        image_data: Optional[list[Any]] = None,
        video_data: Optional[list[Any]] = None,
        bootstrap_host: Optional[str] = None,
        bootstrap_port: Optional[int] = None,
        bootstrap_room: Optional[int] = None,
        session_id: Optional[str] = None,
    ) -> TokenOutput:
        # PD top-level dispatch: prefill mints a bootstrap_room and fans out
        # paired local-prefill + remote-decode calls; decode returns the tokens
        # (prefill only materialises KV and pushes via NIXL). Random peer
        # choice avoids systematic skew from heavy-tailed RL prompt lengths.
        if self._disaggregation_role == "prefill" and self._pd_decode_peers and bootstrap_room is None:
            room = secrets.randbits(63)
            decode_peer = self._pd_decode_peers[secrets.randbelow(len(self._pd_decode_peers))]
            prefill_coro = self.generate(
                prompt_ids,
                dict(sampling_params),
                f"{request_id}_P",
                image_data=image_data,
                video_data=video_data,
                bootstrap_host=self._pd_bootstrap_host,
                bootstrap_port=self._disaggregation_bootstrap_port,
                bootstrap_room=room,
            )
            decode_coro = decode_peer.generate.remote(
                prompt_ids,
                dict(sampling_params),
                f"{request_id}_D",
                image_data=image_data,
                video_data=video_data,
                bootstrap_host=self._pd_bootstrap_host,
                bootstrap_port=self._disaggregation_bootstrap_port,
                bootstrap_room=room,
            )
            _, decode_output = await asyncio.gather(prefill_coro, decode_coro)
            return decode_output

        # TODO(@wuxibin): switch to `/generate` http endpoint once multi-modal support ready.
        max_possible_tokens = self.config.max_model_len - len(prompt_ids) - 1

        if max_possible_tokens < 0:
            raise ValueError(
                f"Prompt length ({len(prompt_ids)}) exceeds the model's maximum context length "
                f"({self.config.max_model_len})."
            )

        if "max_new_tokens" in sampling_params:
            max_new_tokens = sampling_params.pop("max_new_tokens")
        elif "max_tokens" in sampling_params:
            # support vllm-style 'max_tokens' param
            max_new_tokens = sampling_params.pop("max_tokens")
        else:
            # Cap max_tokens by response_length to ensure tensor alignment,
            # and by remaining budget to prevent OOM in multi-turn rollouts.
            max_new_tokens = min(
                self.config.response_length, self.config.prompt_length + self.config.response_length - len(prompt_ids)
            )

        # Clamp max_new_tokens to the valid range [0, max_possible_tokens]
        max_new_tokens = max(0, min(max_new_tokens, max_possible_tokens))

        assert max_new_tokens <= max_possible_tokens, (
            f"max_new_tokens {max_new_tokens} exceeds available context space {max_possible_tokens}"
        )
        sampling_params["max_new_tokens"] = max_new_tokens
        return_logprob = sampling_params.pop("logprobs", False)

        # vLLM-style "prompt_logprobs=K" from the distillation teacher: request
        # input-token logprobs for every position (top-K when K>0, sampled-token
        # logprob only when K==0). Translate to SGLang's per-request logprob API.
        prompt_logprobs = sampling_params.pop("prompt_logprobs", None)
        if prompt_logprobs is not None:
            return_logprob = True

        request = {
            "rid": request_id,
            "input_ids": prompt_ids,
            "sampling_params": sampling_params,
            "return_logprob": return_logprob,
            "image_data": image_data,
            # video_data holds processor features ({"format": "processor_output", ...}) built by
            # the agent loop, not raw frames: SGLang's video_data only accepts a path/url/base64
            # or a dict. Dropping it silently makes the model answer video questions blind.
            "video_data": video_data,
        }

        if prompt_logprobs is not None:
            request["logprob_start_len"] = 0
            if prompt_logprobs > 0:
                request["top_logprobs_num"] = prompt_logprobs

        if self.config.enable_rollout_routing_replay:
            request.update({"return_routed_experts": True})

        # SGLang's scheduler rejects disagg-mode requests without bootstrap_room.
        if bootstrap_room is not None:
            request["bootstrap_host"] = bootstrap_host
            request["bootstrap_port"] = bootstrap_port
            request["bootstrap_room"] = bootstrap_room

        generate_request = GenerateReqInput(**request)

        # Add lora request
        if self.lora_as_adapter:
            generate_request.lora_path = SGLANG_LORA_NAME

        with RLInsightLogger.trace_state(
            "sglang_generate",
            state_lane_id=ray.get_runtime_context().get_actor_name(),
        ):
            output = await self.tokenizer_manager.generate_request(generate_request, None).__anext__()
        meta_info = output.get("meta_info", {})
        finish_reason = meta_info.get("finish_reason")
        finish_reason = finish_reason["type"] if finish_reason else None
        if return_logprob:
            token_ids = list(output.get("output_ids", []))
            output_token_logprobs = meta_info.get("output_token_logprobs") or []
            if output_token_logprobs and len(output_token_logprobs) == len(token_ids):
                log_probs = [float(log_prob) for log_prob, _, _ in output_token_logprobs]
            else:
                # SGLang may return mismatched lengths (e.g. max_new_tokens=0
                # produces a phantom logprob entry with empty output_ids), or
                # an abort may leave an empty logprob payload.
                if len(output_token_logprobs) != len(token_ids):
                    logger.error(
                        f"output_token_logprobs length ({len(output_token_logprobs)}) != "
                        f"output_ids length ({len(token_ids)}) for request {request_id}"
                    )
                token_ids = []
                log_probs = []
        else:
            token_ids = output["output_ids"]
            log_probs = None

        routed_experts = None
        if self.config.enable_rollout_routing_replay:
            if self.config.skip_tokenizer_init:
                # convert to numpy
                captured = output.get("meta_info", {}).get("routed_experts", None)
                routed_experts = captured.numpy() if captured is not None else None
            else:
                from sglang.srt.layers.moe.routed_experts_capturer import extract_routed_experts_from_meta_info

                hf_config = self.model_config.hf_config
                if not hasattr(hf_config, "num_hidden_layers") or not hasattr(hf_config, "num_experts_per_tok"):
                    raise AttributeError(
                        "enable_rollout_routing_replay is set, but hf_config is missing "
                        "'num_hidden_layers' or 'num_experts_per_tok'. This feature requires an MoE model "
                        "configuration that defines these attributes."
                    )
                routed_experts = extract_routed_experts_from_meta_info(output).reshape(
                    -1, hf_config.num_hidden_layers, hf_config.num_experts_per_tok
                )

        extra_fields = {"global_steps": self.global_steps}
        if prompt_logprobs is not None:
            _extract_prompt_logprobs_sglang(
                meta_info=meta_info,
                num_prompt_logprobs=prompt_logprobs,
                sequence_length=len(prompt_ids),
                result_dict=extra_fields,
            )

        # Re-key backend spec-decoding stats to the rollout-common names.
        if self.config.mtp is not None and self.config.mtp.enable and self.config.mtp.enable_rollout:
            extra_fields["spec_num_draft_tokens"] = int(
                meta_info.get("spec_draft_token_num", self.config.mtp.speculative_num_draft_tokens)
            )
            extra_fields["spec_num_accepted_tokens"] = int(meta_info.get("spec_accept_token_num", 0))
            extra_fields["spec_num_verify_steps"] = int(meta_info.get("spec_verify_ct", 0))

        return TokenOutput(
            token_ids=token_ids,
            log_probs=log_probs,
            routed_experts=routed_experts,
            stop_reason=finish_reason,
            extra_fields=extra_fields,
        )

    async def set_global_steps(self, global_steps: int):
        """Set the global steps of the model weights."""
        self.global_steps = global_steps

    async def abort_all_requests(self):
        if self.node_rank != 0:
            return
        await self.tokenizer_manager.pause_generation(PauseGenerationReqInput(mode="abort"))

    async def resume_generation(self):
        if self.node_rank != 0:
            return
        await self.tokenizer_manager.continue_generation(ContinueGenerationReqInput())

    async def start_profile(self, **kwargs):
        if (
            self.profiler_controller.check_enable()
            and self.profiler_controller.check_this_rank()
            and self.profiler_controller.is_discrete_mode()
        ):
            profile_args = build_sglang_profiler_args(
                self.profiler_controller.config, self.profiler_controller.tool_config, self.replica_rank
            )
            tokenizer_manager = getattr(self, "tokenizer_manager", None)
            if tokenizer_manager is None:
                return
            await tokenizer_manager.start_profile(**profile_args)

    async def stop_profile(self):
        if (
            self.profiler_controller.check_enable()
            and self.profiler_controller.check_this_rank()
            and self.profiler_controller.is_discrete_mode()
        ):
            tokenizer_manager = getattr(self, "tokenizer_manager", None)
            if tokenizer_manager is None:
                return
            await tokenizer_manager.stop_profile()
            # Relocate the engine's traces into save_path (when relocate_results is set) so the
            # training worker's single end-of-run upload of the whole save_path picks them up. The
            # rollout engine does not run the finish command itself: it shares save_path with the
            # colocated training worker, so uploading here too would send the same directory twice.
            relocate_rollout_traces(
                self.profiler_controller.config,
                self.replica_rank,
                self.replica_world_size,
                self.profiler_keep_global_ranks,
            )


class SGLangReplica(RolloutReplica):
    def __init__(
        self,
        replica_rank: int,
        config: RolloutConfig,
        model_config: HFModelConfig,
        gpus_per_node: int = 8,
        is_reward_model: bool = False,
        is_teacher_model: bool = False,
        name_suffix: str = "",
    ):
        super().__init__(
            replica_rank, config, model_config, gpus_per_node, is_reward_model, is_teacher_model, name_suffix
        )
        self.server_class = ray.remote(SGLangHttpServer)

    async def launch_servers(self):
        """Launch http server in each node."""
        assert len(self.workers) == self.world_size, (
            f"worker number {len(self.workers)} not equal to world size {self.world_size}"
        )

        # get (node_id, CUDA_VISIBLE_DEVICES) of all workers
        worker_infos = await asyncio.gather(
            *[
                worker.__ray_call__.remote(
                    lambda self: (ray.get_runtime_context().get_node_id(), os.environ[visible_devices_keyword])
                )
                for worker in self.workers
            ]
        )
        worker_cuda_visible_devices = [worker_info[1] for worker_info in worker_infos]
        worker_node_ids = [worker_info[0] for worker_info in worker_infos]
        base_gpu_id = 0
        infer_tp = self.config.tensor_model_parallel_size * self.config.data_parallel_size
        replica_world_size = infer_tp * self.config.pipeline_model_parallel_size
        if os.environ.get(f"RAY_EXPERIMENTAL_NOSET_{visible_devices_keyword}", None):
            logger.warning(f"RAY_EXPERIMENTAL_NOSET_{visible_devices_keyword} is set True!")
            base_gpu_id = (0 + self.replica_rank * replica_world_size) % self.gpus_per_node
        # create server actor in each node with node affinity and cuda visible devices
        for node_rank in range(self.nnodes):
            workers = self.workers[
                node_rank * self.gpus_per_replica_node : (node_rank + 1) * self.gpus_per_replica_node
            ]
            node_cuda_visible_devices_set = worker_cuda_visible_devices[
                node_rank * self.gpus_per_replica_node : (node_rank + 1) * self.gpus_per_replica_node
            ]
            node_cuda_visible_devices = ",".join(
                map(
                    str,
                    sorted(
                        set(
                            int(device)
                            for worker_devices_set in node_cuda_visible_devices_set
                            for device in worker_devices_set.split(",")
                            if device.strip()
                        )
                    ),
                )
            )

            node_id = worker_node_ids[node_rank * self.gpus_per_replica_node]
            if self.is_reward_model:
                name = f"sglang_server_reward_{self.replica_rank}_{node_rank}{self.name_suffix}"
            elif self.is_teacher_model:
                name = f"sglang_server_teacher_{self.replica_rank}_{node_rank}{self.name_suffix}"
            else:
                name = f"sglang_server_{self.replica_rank}_{node_rank}{self.name_suffix}"
            server = self.server_class.options(
                scheduling_strategy=ray.util.scheduling_strategies.NodeAffinitySchedulingStrategy(
                    node_id=node_id,
                    soft=False,
                ),
                runtime_env={
                    "env_vars": {
                        **{var: "1" for var in get_platform().ray_noset_envvars()},
                        **get_platform().rollout_env_vars(),
                    }
                },
                name=name,
                max_concurrency=self.config.ray_actor_max_concurrency,
            ).remote(
                config=self.config,
                model_config=self.model_config,
                rollout_mode=self.rollout_mode,
                workers=workers,
                replica_rank=self.replica_rank,
                node_rank=node_rank,
                nnodes=self.nnodes,
                cuda_visible_devices=node_cuda_visible_devices,
                base_gpu_id=base_gpu_id,
            )
            self.servers.append(server)

        # launch http server in each node
        master_address, master_port = None, None
        if self.nnodes > 1:
            master_address, master_port = await self.servers[0].get_master_address.remote()
        await asyncio.gather(
            *[
                server.launch_server.remote(master_address=master_address, master_port=master_port)
                for server in self.servers
            ]
        )

        # get http server address from first server
        server_address, server_port = await self.servers[0].get_server_address.remote()
        self._server_handle = self.servers[0]
        self._server_address = (
            f"[{server_address}]:{server_port}"
            if is_valid_ipv6_address(server_address)
            else f"{server_address}:{server_port}"
        )

    async def abort_all_requests(self, reject_request: bool = False):
        """Abort all ongoing generation requests on the primary server.

        SGLang control RPCs are only served by the node-rank 0 server for a
        multi-node replica, so avoid broadcasting this call to every server.
        """
        if reject_request:
            # SGLang blocks new requests inside its own tokenizer manager, so verl has no
            # admission point to fail them at. Requests routed here after the pause wait
            # until continue_generation(). TODO: add a verl-side gate in front of
            # tokenizer_manager.pause_generation() so this replica can reject them too.
            logger.warning(
                "SGLang rollout ignores reject_request=True: requests arriving while generation "
                "is paused will wait for the next resume_generation() instead of failing over."
            )
        await self.servers[0].abort_all_requests.remote()

    async def resume_generation(self):
        """Resume generation on the primary server after abort_all_requests."""
        await self.servers[0].resume_generation.remote()
