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
"""Bit-identity tests for the SGLang custom-weight-loader delta apply.

Builds sparse ``indices``-encoding flushes exactly as the sharded engines
assemble them (int32 within-parameter flat positions viewed as bytes + a value
stream + checksum) and feeds each through :func:`delta_loader.apply_delta`
against a stand-in model whose ``load_weights`` mimics SGLang's
``param.copy_(loaded)`` semantics. Verifies the masked in-place apply: changed
positions land bit-exactly, and positions outside the delta are never touched.
"""

from __future__ import annotations

import json

import torch

from verl.checkpoint_engine.delta_sync import DeltaParam, checksum
from verl.workers.rollout.sglang_rollout.delta_loader import apply_delta


class _FakeModel:
    """Holds live params; load_weights lands on param.copy_(loaded), like SGLang."""

    def __init__(self, named: list[tuple[str, torch.Tensor]]):
        self.params = {n: t.clone() for n, t in named}

    def parameters(self):
        return iter(self.params.values())

    def named_buffers(self):
        return iter([])

    def load_weights(self, chunk):
        for name, tensor in chunk:
            self.params[name].copy_(tensor)


def _make_named(dtype=torch.bfloat16) -> list[tuple[str, torch.Tensor]]:
    torch.manual_seed(0)
    return [
        ("layer.0.weight", torch.randn(64, 32, dtype=dtype)),
        ("layer.1.weight", torch.randn(32, 16, dtype=dtype)),
    ]


def _sparse_indices_flush(old_named, new_named):
    """Assemble one indices-encoding flush from a bytewise old/new diff --
    the same layout the sharded engines' ``_assemble_flush`` produces."""
    params, idx_pieces, val_pieces = [], [], []
    pos_off = val_off = 0
    for (name, old), (_, new) in zip(old_named, new_named, strict=True):
        fo, fn = old.reshape(-1), new.reshape(-1)
        changed = (fo.view(torch.uint8).view(fo.numel(), -1) != fn.view(torch.uint8).view(fn.numel(), -1)).any(dim=-1)
        idx = changed.nonzero(as_tuple=False).view(-1)
        if idx.numel() == 0:
            continue
        nnz = int(idx.numel())
        idx_pieces.append(idx.to(torch.int32))
        val_pieces.append(fn[idx])
        params.append(
            DeltaParam(
                name=name,
                dtype=str(new.dtype).replace("torch.", ""),
                shape=list(new.shape),
                pos_start=pos_off,
                pos_end=pos_off + nnz * 4,
                pos_width=4,
                val_start=val_off,
                val_end=val_off + nnz,
            )
        )
        pos_off += nnz * 4
        val_off += nnz
    positions = torch.cat(idx_pieces).contiguous().view(torch.uint8)
    values = torch.cat(val_pieces)
    return params, positions, values


def _named_tensors(params, positions, values, encoding="indices"):
    spec = {
        "encoding": encoding,
        "params": [vars(p) for p in params],
        "checksum": int(checksum(positions, values)),
    }
    spec_t = torch.frombuffer(bytearray(json.dumps(spec).encode()), dtype=torch.uint8)
    out = [("__delta_spec__", spec_t), ("__values__", values.clone())]
    if positions.numel():
        out.insert(1, ("__positions__", positions.clone()))
    return out


def test_masked_apply_bit_identical():
    named = _make_named()
    model = _FakeModel(named)

    new_named = []
    for name, t in named:
        new = t.clone()
        flat = new.view(-1)
        idx = torch.tensor([1, 17, 200, 511], dtype=torch.int64) % flat.numel()
        flat[idx] = flat[idx] + 0.5
        new_named.append((name, new))

    apply_delta(model, _named_tensors(*_sparse_indices_flush(named, new_named)))

    for name, expected in new_named:
        got = model.params[name]
        assert torch.equal(got.view(torch.int16), expected.view(torch.int16)), f"{name} not bit-identical"


def test_untouched_positions_preserved():
    """Positions absent from the delta must keep the model's LIVE values (not the
    trainer snapshot's) -- proves the apply is masked, not a full overwrite."""
    named = _make_named()
    model = _FakeModel(named)
    # Poison one untouched position in the live model; a full overwrite would revert it.
    sentinel_name = named[0][0]
    model.params[sentinel_name].view(-1)[3] = 42.0

    new_named = []
    for name, t in named:
        new = t.clone()
        new.view(-1)[7] = new.view(-1)[7] + 1.0  # change only position 7
        new_named.append((name, new))

    apply_delta(model, _named_tensors(*_sparse_indices_flush(named, new_named)))

    live = model.params[sentinel_name].view(-1)
    assert live[3].item() == 42.0, "masked apply must not touch positions outside the delta"
    assert live[7] == new_named[0][1].view(-1)[7]


def test_checksum_mismatch_raises():
    import pytest

    named = _make_named()
    new_named = [(n, t + 0.5) for n, t in named]
    named_tensors = _named_tensors(*_sparse_indices_flush(named, new_named))
    named_tensors[2][1].view(torch.uint8)[0] ^= 0xFF  # corrupt one value byte
    with pytest.raises(RuntimeError, match="checksum"):
        apply_delta(_FakeModel(named), named_tensors)


def test_dense_flush_applies_full_tensors():
    """Dense (first-sync) flushes carry values only; the loader must apply them verbatim."""
    named = _make_named()
    model = _FakeModel([(n, torch.zeros_like(t)) for n, t in named])  # dummy init

    params, pieces, val_off = [], [], 0
    for name, t in named:
        flat = t.contiguous().view(-1)
        params.append(
            {
                "name": name,
                "dtype": str(t.dtype).replace("torch.", ""),
                "shape": list(t.shape),
                "pos_start": 0,
                "pos_end": 0,
                "pos_width": 4,
                "val_start": val_off,
                "val_end": val_off + flat.numel(),
            }
        )
        pieces.append(flat)
        val_off += flat.numel()
    values = torch.cat(pieces)

    spec = {"encoding": "dense", "params": params, "checksum": int(checksum(torch.empty(0, dtype=torch.uint8), values))}
    spec_t = torch.frombuffer(bytearray(json.dumps(spec).encode()), dtype=torch.uint8)
    apply_delta(model, [("__delta_spec__", spec_t), ("__values__", values)])

    for name, expected in named:
        assert torch.equal(model.params[name].view(torch.int16), expected.view(torch.int16)), name


def _dense_verify_flush(named, is_last=True, verify=True):
    params, pieces, val_off = [], [], 0
    for name, t in named:
        flat = t.contiguous().view(-1)
        params.append(
            {
                "name": name,
                "dtype": str(t.dtype).replace("torch.", ""),
                "shape": list(t.shape),
                "pos_start": 0,
                "pos_end": 0,
                "pos_width": 4,
                "val_start": val_off,
                "val_end": val_off + flat.numel(),
            }
        )
        pieces.append(flat)
        val_off += flat.numel()
    values = torch.cat(pieces)
    spec = {
        "encoding": "dense",
        "verify": verify,
        "is_last": is_last,
        "params": params,
        "checksum": int(checksum(torch.empty(0, dtype=torch.uint8), values)),
    }
    spec_t = torch.frombuffer(bytearray(json.dumps(spec).encode()), dtype=torch.uint8)
    return [("__delta_spec__", spec_t), ("__values__", values)]


def test_verify_sweep_passes_on_identical_state():
    """A verify flush against a bit-identical model reports zero mismatches."""
    named = _make_named()
    model = _FakeModel([(n, t.clone()) for n, t in named])
    apply_delta(model, _dense_verify_flush(named))  # must not raise


def test_verify_sweep_fails_loud_on_divergence():
    """A single flipped element in the server state must fail the sweep."""
    import pytest

    named = _make_named()
    diverged = [(n, t.clone()) for n, t in named]
    diverged[1][1].view(-1)[3] += 1.0
    model = _FakeModel(diverged)
    with pytest.raises(RuntimeError, match="verification FAILED"):
        apply_delta(model, _dense_verify_flush(named))


def test_masked_copy_guard_spares_non_model_storage():
    """Guard (a): NaN-skip semantics apply ONLY to the model's own param/buffer
    storage. A foreign same-shape floating tensor copied inside the window must
    go through the original copy_ (NaNs land), not be masked."""
    from verl.workers.rollout.sglang_rollout.delta_loader import _masked_copy

    named = _make_named()
    model = _FakeModel(named)
    param = model.params[named[0][0]]
    live_before = param.detach().clone()

    foreign = torch.zeros_like(param)

    with _masked_copy(model):
        nan_src = torch.full(param.shape, float("nan"), dtype=param.dtype)
        nan_src.view(-1)[0] = 1.0
        param.copy_(nan_src)
        foreign.copy_(nan_src)

    # Model param: changed position landed, NaN positions kept live values.
    assert param.view(-1)[0].item() == 1.0
    assert torch.equal(param.view(-1)[1:], live_before.view(-1)[1:])
    # Foreign tensor: passthrough -- NaNs were written as a plain copy would.
    assert torch.isnan(foreign.view(-1)[1:]).all()
    assert foreign.view(-1)[0].item() == 1.0


def test_masked_copy_guard_covers_model_buffers():
    """Guard (a) must treat registered buffers as model storage too."""
    from verl.workers.rollout.sglang_rollout.delta_loader import _masked_copy

    class _ModelWithBuffer(_FakeModel):
        def __init__(self):
            super().__init__(_make_named())
            self.buffers_ = {"kv_scale": torch.ones(16, dtype=torch.bfloat16)}

        def named_buffers(self):
            return iter(self.buffers_.items())

    model = _ModelWithBuffer()
    buf = model.buffers_["kv_scale"]
    live_before = buf.detach().clone()

    with _masked_copy(model):
        nan_src = torch.full((16,), float("nan"), dtype=torch.bfloat16)
        nan_src.view(-1)[2] = 5.0
        buf.copy_(nan_src)

    assert buf.view(-1)[2].item() == 5.0
    assert torch.equal(buf.view(-1)[:2], live_before.view(-1)[:2])
    assert torch.equal(buf.view(-1)[3:], live_before.view(-1)[3:])


def test_masked_copy_guard_covers_strided_view_storage():
    """Guard (a): a registered tensor's protection must cover its FULL underlying
    storage, not numel*element_size() from its data_ptr. A narrowed registered
    tensor leaves the storage tail outside that nominal span; copies into the
    tail (e.g. through a sibling view) must still be masked."""
    import torch.nn as nn

    from verl.workers.rollout.sglang_rollout.delta_loader import _masked_copy

    class _Model(nn.Module):
        pass

    big = torch.zeros(200, dtype=torch.bfloat16)  # storage: 200 elements
    model = _Model()
    model.register_buffer("narrow_param", big[50:150])  # nominal span: [50, 150)

    tail = big[160:170]  # same storage, past the nominal span, inside storage
    with _masked_copy(model):
        nan_src = torch.full(tail.shape, float("nan"), dtype=torch.bfloat16)
        nan_src.view(-1)[0] = 7.0
        tail.copy_(nan_src)

    assert tail.view(-1)[0].item() == 7.0  # changed position landed
    assert not torch.isnan(tail.view(-1)[1:]).any(), (
        "tail lives in the registered tensor's storage: NaN skip must apply"
    )
    assert torch.equal(tail.view(-1)[1:], torch.zeros_like(tail.view(-1)[1:]))


def test_masked_copy_guard_overlapping_spans_do_not_shadow():
    """Guard (a): when registered tensors overlap (a long buffer and a slice of
    it), the shorter span must not shadow the longer one for addresses past its
    end but still inside the longer buffer."""
    import torch.nn as nn

    from verl.workers.rollout.sglang_rollout.delta_loader import _masked_copy

    class _Model(nn.Module):
        pass

    big = torch.zeros(100, dtype=torch.bfloat16)
    model = _Model()
    model.register_buffer("long_buf", big[0:100])
    model.register_buffer("short_buf", big[50:60])  # overlapping view

    target = big[60:70]  # inside long_buf, outside short_buf's nominal span
    with _masked_copy(model):
        nan_src = torch.full(target.shape, float("nan"), dtype=torch.bfloat16)
        nan_src.view(-1)[0] = 3.0
        target.copy_(nan_src)

    assert target.view(-1)[0].item() == 3.0
    assert torch.equal(
        target.view(-1)[1:], torch.zeros_like(target.view(-1)[1:])
    ), "address past the short span but inside the long buffer must still be masked"
