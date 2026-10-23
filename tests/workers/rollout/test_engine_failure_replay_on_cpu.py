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
"""Exercise native client replay and routing with GPU-free RPC adapters."""

import asyncio
import inspect
from types import SimpleNamespace

import pytest
from omegaconf import OmegaConf
from ray.exceptions import ActorDiedError

# The generic CPU extra omits vLLM; vllm.yml runs this module with that backend.
pytest.importorskip("vllm")

from vllm.v1.engine.exceptions import EngineDeadError

from verl.workers.rollout.llm_server import FullyAsyncLLMServerClient, LLMServerClient
from verl.workers.rollout.replica import TokenOutput
from verl.workers.rollout.router import GlobalRequestLoadBalancer


class _Handle:
    """Schedule actor-like calls, including fire-and-forget release, locally."""

    def __init__(self, target):
        self.target = target

    def __getattr__(self, name):
        async def call(*args, **kwargs):
            value = getattr(self.target, name)(*args, **kwargs)
            return await value if inspect.isawaitable(value) else value

        return SimpleNamespace(remote=lambda *args, **kwargs: asyncio.create_task(call(*args, **kwargs)))


def _config():
    return OmegaConf.create({"actor_rollout_ref": {"rollout": {"name": "vllm", "response_length": 4}}})


@pytest.mark.parametrize("client_class", [LLMServerClient, FullyAsyncLLMServerClient])
@pytest.mark.parametrize("failure", ["partial", "actor_death", "engine_dead"])
def test_pending_generation_replays_after_owner_publishes_replacement(client_class, failure):
    async def main():
        calls = []

        async def failed(**kwargs):
            calls.append({**kwargs, "sampling_params": dict(kwargs["sampling_params"])})
            if failure == "actor_death":
                raise ActorDiedError()
            if failure == "engine_dead":
                raise EngineDeadError()
            return TokenOutput(
                token_ids=[7, 8],
                log_probs=[-0.1, -0.2],
                stop_reason="aborted",
                extra_fields={"engine_failed": True, "global_steps": 4},
            )

        async def healthy(**kwargs):
            calls.append({**kwargs, "sampling_params": dict(kwargs["sampling_params"])})
            tokens = [9, 10] if len(kwargs["prompt_ids"]) == 5 else [7, 8, 9, 10]
            return TokenOutput(
                token_ids=tokens,
                log_probs=[-0.3] * len(tokens),
                stop_reason="completed",
                extra_fields={"global_steps": 5 if client_class is FullyAsyncLLMServerClient else 4},
            )

        old, new = _Handle(SimpleNamespace(generate=failed)), _Handle(SimpleNamespace(generate=healthy))
        router = GlobalRequestLoadBalancer({"same-address": old})
        client = client_class(_config(), _Handle(router), engine_recovery_timeout=5)
        params = {"max_tokens": 4, "logprobs": True}

        async def owner():
            while router.get_all_servers():
                await asyncio.sleep(0)
            router.add_servers({"same-address": new})
            # A late failure or release must leave this new actor untouched.
            assert not router.remove_server_if_current("same-address", old)
            router.acquire_server("other-session")
            router.release_server("same-address", expected_handle=old)
            assert router.get_inflight_count("same-address") == 1
            router.release_server("same-address", expected_handle=new)

        # Bound the owner as well as generation: a missing route removal must fail
        # instead of leaving the owner polling forever after generation finishes.
        result, _ = await asyncio.wait_for(
            asyncio.gather(
                client.generate("session", prompt_ids=[1, 2, 3], sampling_params=params),
                owner(),
            ),
            timeout=3,
        )
        await asyncio.sleep(0)
        assert len(calls) == 2 and result.token_ids == [7, 8, 9, 10]
        assert len(result.log_probs) == 4
        assert result.stop_reason == ("length" if client_class is FullyAsyncLLMServerClient else "completed")
        assert calls[0]["prompt_ids"] == [1, 2, 3]
        if client_class is FullyAsyncLLMServerClient and failure == "partial":
            assert calls[1]["prompt_ids"] == [1, 2, 3, 7, 8]
            assert calls[1]["sampling_params"]["max_tokens"] == 2
            assert result.log_probs[:2] == [-0.1, -0.2]
            assert result.extra_fields["min_global_steps"] == 4 and result.extra_fields["max_global_steps"] == 5
        else:
            assert calls[1]["prompt_ids"] == [1, 2, 3]
            assert calls[1]["sampling_params"]["max_tokens"] == 4
            if client_class is FullyAsyncLLMServerClient:
                assert result.extra_fields["min_global_steps"] == 5
                assert result.extra_fields["max_global_steps"] == 5
        assert params == {"max_tokens": 4, "logprobs": True}
        assert router.get_inflight_count("same-address") == 0

    asyncio.run(main())


@pytest.mark.parametrize("timeout", [0, -1, float("inf"), float("-inf"), float("nan")])
def test_engine_replay_rejects_invalid_timeout(timeout):
    with pytest.raises(ValueError, match="positive.*finite"):
        LLMServerClient(_config(), _Handle(GlobalRequestLoadBalancer({})), engine_recovery_timeout=timeout)


@pytest.mark.parametrize("error,recovery_timeout", [(ValueError("invalid request"), 5), (EngineDeadError(), None)])
def test_errors_outside_enabled_engine_replay_propagate(error, recovery_timeout):
    async def main():
        async def failed(**kwargs):
            raise error

        server = _Handle(SimpleNamespace(generate=failed))
        router = GlobalRequestLoadBalancer({"server": server})
        client = LLMServerClient(_config(), _Handle(router), engine_recovery_timeout=recovery_timeout)
        with pytest.raises(type(error)):
            await client.generate("session", prompt_ids=[1], sampling_params={"max_tokens": 4})
        await asyncio.sleep(0)
        assert router.get_all_servers() == ["server"] and router.get_inflight_count("server") == 0

    asyncio.run(main())


@pytest.mark.parametrize("timeout,retries,error", [(0.02, 3, TimeoutError), (1, 0, RuntimeError)])
def test_engine_replay_stops_at_wait_or_retry_limit(timeout, retries, error):
    async def main():
        async def failed(**kwargs):
            return TokenOutput(token_ids=[], stop_reason="aborted", extra_fields={"engine_failed": True})

        router = GlobalRequestLoadBalancer({"failed": _Handle(SimpleNamespace(generate=failed))})
        client = LLMServerClient(
            _config(), _Handle(router), engine_recovery_timeout=timeout, max_engine_retries=retries
        )
        # The outer guard fails the test if the recovery limit itself stops working.
        task = asyncio.create_task(client.generate("session", prompt_ids=[1], sampling_params={"max_tokens": 4}))
        done, _ = await asyncio.wait([task], timeout=2)
        if not done:
            task.cancel()
            pytest.fail("engine replay did not terminate within its recovery limit")
        with pytest.raises(error):
            await task
        await asyncio.sleep(0)
        assert router.get_all_servers() == []

    asyncio.run(main())
