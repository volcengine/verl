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
"""Transport-agnostic delta sync pipeline: bucketing, batching, state machine.

Everything here is plain torch and ``torch.distributed`` (the trainer-side
gather runs on the training engine's own process groups), so the NCCL/CUDA
engine and the HCCL/NPU engine share it. A concrete engine combines
``DeltaSyncMixin`` with a transport parent (``NCCLCheckpointEngine`` /
``HCCLCheckpointEngine``, which contribute the zmq PUB/SUB manifest channel,
rendezvous and topology) and implements the transport hooks:

* ``_ensure_wire()`` -- transport lazy-init before the first manifest (no-op default)
* ``_broadcast_flush(pos_u8, val_u8)`` -- put one flush's raw buffers on the wire
* ``_release_after_round(phase)`` -- return transport scratch memory after a round
* ``_wire_device`` -- device (str or torch.device) where flush tensors live

Data ladder (sender side, steady) -- names anchor the pieces in this module::

    backend HF delta ENTRY (slots, dtype, counts, hf_idx, hf_val, group)
    --_GatherQueue--> per-SLOT delta on rank 0 --_bucket_*--> _FlushPiece
    --_FlushBucket--> FLUSH (DeltaFlush) --_publish_flush--> wire
"""

from __future__ import annotations

import logging
import time
from collections.abc import Generator
from dataclasses import dataclass

import torch
import zmq

from .encode import DeltaFlush, DeltaParam
from .encode import checksum as _checksum
from .sparse_gather import gather_slot_entries_to_rank0

logger = logging.getLogger(__name__)


def _prodshape(shape) -> int:
    n = 1
    for x in shape:
        n *= int(x)
    return n


@dataclass(slots=True)
class _FlushPiece:
    """One (possibly sliced) per-parameter piece buffered for a pending indices flush."""

    name: str
    dtype_str: str
    shape: list
    idx: torch.Tensor
    val: torch.Tensor


@dataclass(slots=True)
class _ValuesPiece:
    """One whole parameter's flat values buffered for the seed sync's values-only flush."""

    name: str
    dtype_str: str
    shape: list
    flat: torch.Tensor


class _FlushBucket:
    """One-flush-lookahead bucket pipeline, shared by the steady loop and both
    seed streams. Pieces accumulate until ``cap`` bytes; ``seal`` assembles them
    into the single pending flush, first emitting the previous pending with
    ``is_last=False`` (the lookahead: only the caller's finale knows which flush
    is last and emits it with ``is_last=True``). ``assemble`` and ``publish``
    carry the only real differences between the streams -- the wire format
    (indexed flush vs values-only flush) and the flush counters."""

    __slots__ = ("cap", "pieces", "nbytes", "pending", "_assemble", "_publish")

    def __init__(self, cap: int, assemble, publish):
        self.cap = int(cap)
        self.pieces: list = []
        self.nbytes = 0
        self.pending = None
        self._assemble = assemble
        self._publish = publish

    def add(self, piece, nbytes: int) -> None:
        self.pieces.append(piece)
        self.nbytes += int(nbytes)
        if self.nbytes >= self.cap:
            self.seal()

    def seal(self) -> None:
        if not self.pieces:
            return
        self.emit(is_last=False)
        self.pending = self._assemble(self.pieces)
        self.pieces, self.nbytes = [], 0

    def emit(self, is_last: bool) -> None:
        if self.pending is not None:
            self._publish(self.pending, is_last)
            self.pending = None


def _bucket_sliced(bkt: _FlushBucket, name: str, dtype_str: str, shape, aidx: torch.Tensor, aval: torch.Tensor) -> None:
    """Slice one param's (idx, val) delta into <= MAX_ENTRY_ELEMS pieces and bucket
    them (bounds the receiver-side decode transient; the masked apply is sequential,
    so splitting is transparent). Bucket bytes = actual wire bytes (int32 positions
    + values)."""
    max_elems = DeltaSyncMixin.MAX_ENTRY_ELEMS
    for s in range(0, aidx.numel(), max_elems):
        e = min(s + max_elems, aidx.numel())
        bkt.add(
            _FlushPiece(name, dtype_str, list(shape), aidx[s:e], aval[s:e]),
            (e - s) * (4 + aval.element_size()),
        )


class _GatherQueue:
    """Per-gather-group batching of slot-keyed queue entries
    ``(slots, dtype_str, counts, idx, val)``. Entries carry FINAL-coordinate
    payloads (identity specs: one slot = the param itself; converter specs: the
    spec's hf_slots), so rank 0 never converts -- ``consume`` receives assembled
    per-slot pieces straight from the gather.

    One queue per ProcessGroup: separate queues stop pg alternation (dense fsdp
    group vs expert world group per layer) from shattering batches. The flush
    trigger is COUNT-ONLY: entry counts are identical on every rank while byte
    totals are not, so a count trigger is the only one that keeps the collective
    sequence identical across ranks (a per-rank byte trigger desyncs the gathers
    and deadlocks NCCL). Byte bounding happens INSIDE the batched gather via
    ``max_round_bytes``, decided from the all-gathered counts every rank sees."""

    __slots__ = ("batch_k", "max_round_bytes", "is_r0", "_consume", "_queues")

    def __init__(self, batch_k: int, max_round_bytes: int, is_r0: bool, consume):
        self.batch_k = max(int(batch_k), 1)
        self.max_round_bytes = int(max_round_bytes)
        self.is_r0 = is_r0
        self._consume = consume
        self._queues: dict[int, tuple] = {}  # id(pg) -> (pg, [entries])

    def put(self, pg, slots: list, dtype_str: str, counts: torch.Tensor, idx: torch.Tensor, val: torch.Tensor):
        _pg, entries = self._queues.setdefault(id(pg), (pg, []))
        entries.append((slots, dtype_str, counts, idx, val))
        if len(entries) >= self.batch_k:
            self._flush(pg, entries)

    def flush_all(self) -> None:
        for pg, entries in self._queues.values():
            self._flush(pg, entries)

    def _flush(self, pg, entries: list) -> None:
        """One gather round for one group's queue."""
        if not entries:
            return
        batch = list(entries)
        entries.clear()
        if pg is None:
            # unsharded/replicated params: rank 0's local delta already is global
            if self.is_r0:
                for slots, dtype_str, counts, idx, val in batch:
                    off = 0
                    for (name, shape), c in zip(slots, counts.tolist(), strict=True):
                        self._consume(
                            name, dtype_str, tuple(shape), _prodshape(shape), idx[off : off + c], val[off : off + c]
                        )
                        off += c
            return
        dev = batch[0][3].device
        counts_concat = torch.cat([c for _, _, c, _, _ in batch]).to(dev)
        idx_concat = torch.cat([i for _, _, _, i, _ in batch])
        val_concat = torch.cat([v for _, _, _, _, v in batch])
        gathered = gather_slot_entries_to_rank0(
            idx_concat, val_concat, counts_concat, group=pg, max_round_bytes=self.max_round_bytes
        )
        if self.is_r0 and gathered is not None:
            slot_i = 0
            for slots, dtype_str, _counts, _i, _v in batch:
                for name, shape in slots:
                    aidx, aval = gathered[slot_i]
                    slot_i += 1
                    self._consume(name, dtype_str, tuple(shape), _prodshape(shape), aidx, aval)


class DeltaSyncMixin:
    """The delta sync state machine (seed -> steady), bucketing and metrics.

    ``send_weights`` takes the TRAINING ENGINE and drives the sync itself: the
    seed (first sync) streams the backend's full ``get_per_tensor_param()``
    export over the values-only wire and pins the diff base
    (``prime_delta_snapshots``); every steady sync consumes the backend's HF
    delta export ``get_per_tensor_param_delta_shard()`` -- per-parameter
    FINAL-HF-coordinate entries ``(slots, dtype_str, counts, hf_idx, hf_val,
    gather_group)``. Naming, to-HF conversion, diff and snapshot all live on
    the backend side (see :mod:`verl.workers.engine.utils`); this mixin only
    batches, gathers, buckets and ships, and so serves any backend that can
    produce HF deltas.
    """

    # Cap on changed elements per DeltaParam entry. The receiver-side decode
    # densifies per entry with an int64 index transient (8 B/element), so an
    # uncapped entry (e.g. a 7B model's whole embedding on the full seed, ~545M
    # elements) would spike several GiB at once. Oversized per-param deltas are
    # sliced into multiple entries (the masked apply is sequential, so splitting
    # is transparent); 64M elements bounds the transient to ~512 MiB.
    MAX_ENTRY_ELEMS = 64 << 20

    def __init__(self, *args, encoding: str = "indices", batch_gather: int = 32, verify_every: int = 0, **kwargs):
        super().__init__(*args, **kwargs)
        assert encoding == "indices", f"delta_sharded ships only the 'indices' position encoding; got {encoding!r}"
        self.encoding = encoding
        # SGLang supports verify_every > 0; vLLM rejects it at startup.
        self.verify_every = int(verify_every)
        self._shard_seeded = False
        # Gather the per-param sparse deltas in groups of this many parameters
        # (one count-matrix all_gather + two padded gathers per group instead of
        # three collectives per parameter).
        self.batch_gather = int(batch_gather)

    # ---- transport hooks (implemented by the concrete engine) ----

    @property
    def _wire_device(self):
        """Device (str or torch.device) where flush tensors are assembled and broadcast from."""
        raise NotImplementedError

    def _broadcast_flush(self, pos_u8: torch.Tensor | None, val_u8: torch.Tensor) -> None:
        """Put one flush's raw uint8 buffers on the wire (positions may be absent for values-only flushes)."""
        raise NotImplementedError

    def _ensure_wire(self) -> None:
        """Transport lazy-init, invoked BEFORE each flush's manifest is published.

        The HCCL engine builds its communicator here: the lazily built group
        completes only once every receiver joined, and every receiver connects
        its zmq SUB before joining, so "group ready" implies "subscribed" --
        which is what makes publishing the manifest after this hook lossless
        (a zmq PUB drops messages that predate their subscribers). Transports
        that set the wire up eagerly (the NCCL group) leave this as a no-op.
        """

    def _release_after_round(self, phase: str) -> None:
        raise NotImplementedError

    # ---- shared streaming wire ----
    # Stream each flush as soon as it is produced so trainer peak memory stays near two buckets,
    # including during the full seed. Each ZMQ manifest + transport broadcast carries ``is_last``;
    # rollout adapters then forward that flush over same-GPU IPC to their backend-specific consumer.
    def _publish_flush(self, flush: DeltaFlush, first: bool, is_last: bool) -> None:
        meta = {
            "is_full": first,
            "encoding": self.encoding,
            "is_last": is_last,
            "terminal_empty": False,
            "pos_numel": int(flush.positions_cpu.numel()),
            "val_numel": int(flush.values_gpu.numel()),
            "val_dtype": str(flush.values_gpu.dtype).replace("torch.", ""),
            "spec": {
                "encoding": self.encoding,
                "params": [vars(p) for p in flush.params],
                "checksum": int(flush.checksum),
            },
        }
        self._ensure_wire()
        self.socket.send_string(self.topic, flags=zmq.SNDMORE)
        self.socket.send_pyobj(meta)
        pos_u8 = flush.positions_cpu.to(self._wire_device, non_blocking=True).contiguous().view(torch.uint8)
        val_u8 = flush.values_gpu.contiguous().view(torch.uint8)
        self._broadcast_flush(pos_u8, val_u8)

    def _publish_values_flush(
        self, params: list[DeltaParam], values: torch.Tensor, is_last: bool, verify: bool = False
    ) -> None:
        """Publish a values-only (full-coverage, positions-free) flush -- used by the first
        sync. The wire encoding tag stays ``"dense"`` -- it is protocol, shared with the
        receiver's delta_loader decode."""
        values = values.contiguous()
        empty_pos = torch.empty(0, dtype=torch.uint8, device=values.device)
        meta = {
            "is_full": True,
            "encoding": "dense",
            "is_last": is_last,
            "terminal_empty": False,
            "pos_numel": 0,
            "val_numel": int(values.numel()),
            "val_dtype": str(values.dtype).replace("torch.", ""),
            "spec": {
                "encoding": "dense",
                "verify": verify,
                "is_last": is_last,
                "params": [vars(p) for p in params],
                "checksum": int(_checksum(empty_pos, values)),
            },
        }
        self._ensure_wire()
        self.socket.send_string(self.topic, flags=zmq.SNDMORE)
        self.socket.send_pyobj(meta)
        self._broadcast_flush(None, values.view(torch.uint8))

    def _publish_terminal(self, first: bool) -> None:
        """End-of-stream marker when zero flushes were produced (no broadcast, just a signal)."""
        meta = {"is_full": first, "encoding": self.encoding, "is_last": True, "terminal_empty": True}
        self._ensure_wire()
        self.socket.send_string(self.topic, flags=zmq.SNDMORE)
        self.socket.send_pyobj(meta)

    def _verify_due(self) -> bool:
        """True on every K-th steady sync when constructed with ``verify_every=K``."""
        if self.verify_every <= 0:
            return False
        self._steady_count = getattr(self, "_steady_count", 0) + 1
        return self._steady_count % self.verify_every == 0

    def _assemble_flush(self, per_param: list[_FlushPiece]) -> DeltaFlush:
        """Build one DeltaFlush (indices encoding) from rank 0's gathered per-param deltas.

        ``per_param``: :class:`_FlushPiece` entries whose ``idx`` are within-parameter
        flat positions (== what the receiver decodes).

        Positions stay on the device end to end (int32 pieces -> one cat -> uint8 view);
        the wire broadcasts from the device anyway, and a host round-trip here
        (``.cpu().numpy().tobytes()`` + join) dominated the whole send at scale
        (~2.4s/sync at 7B steady state, ~83s on the full seed).
        """
        idx_pieces: list[torch.Tensor] = []
        val_pieces: list[torch.Tensor] = []
        params: list[DeltaParam] = []
        pos_off = val_off = 0
        for piece in per_param:
            nnz = int(piece.idx.numel())
            # positions ride the wire as int32 (pos_width=4); a parameter bigger than
            # 2^31 elements would silently wrap, so fail loud instead. DeltaParam
            # carries pos_width for a future 8-byte escalation if a model needs it.
            assert _prodshape(piece.shape) < (1 << 31), (
                f"{piece.name}: {_prodshape(piece.shape)} elements exceeds the int32 position encoding"
            )
            idx_pieces.append(piece.idx.to(torch.int32))
            val_pieces.append(piece.val)
            params.append(
                DeltaParam(
                    name=piece.name,
                    dtype=piece.dtype_str,
                    shape=list(piece.shape),
                    pos_start=pos_off,
                    pos_end=pos_off + nnz * 4,
                    pos_width=4,
                    val_start=val_off,
                    val_end=val_off + nnz,
                )
            )
            pos_off += nnz * 4
            val_off += nnz

        values_gpu = (
            torch.cat(val_pieces) if val_pieces else torch.empty(0, dtype=self.rollout_dtype, device=self._wire_device)
        )
        positions_u8 = (
            torch.cat(idx_pieces).contiguous().view(torch.uint8)
            if idx_pieces
            else torch.empty(0, dtype=torch.uint8, device=values_gpu.device)
        )
        cks = _checksum(positions_u8, values_gpu)
        return DeltaFlush(
            encoding=self.encoding, params=params, positions_cpu=positions_u8, values_gpu=values_gpu, checksum=cks
        )

    def _send_full_seed(
        self,
        weights: Generator[tuple[str, torch.Tensor], None, None],
        global_steps: int | None = None,
        verify: bool = False,
    ) -> dict[str, float] | None:
        """First sync: stream the backend's FULL HF export over the values-only wire.

        ``weights`` is ``get_per_tensor_param()`` -- every backend already knows how
        to assemble and convert its own full tensors (FSDP all-gather, veomni expert
        restack, Megatron TP/PP fusion), so the seed inherits all of that for free
        and this engine only buckets and broadcasts. Every trainer rank iterates the
        generator (the per-tensor assembly is collective); rank 0 buckets. Resume
        works by construction: whatever the trainer restored is what ships."""
        is_r0 = self.is_master
        t0 = time.time()
        n_flushes = 0
        total_elems = 0
        wire_bytes = 0

        def _assemble_values(pieces: list[_ValuesPiece]):
            params = []
            val_off = 0
            for piece in pieces:
                n = int(piece.flat.numel())
                params.append(
                    DeltaParam(
                        name=piece.name,
                        dtype=piece.dtype_str,
                        shape=list(piece.shape),
                        pos_start=0,
                        pos_end=0,
                        pos_width=4,
                        val_start=val_off,
                        val_end=val_off + n,
                    )
                )
                val_off += n
            return params, torch.cat([piece.flat for piece in pieces])

        def _publish_values(pending, is_last: bool) -> None:
            nonlocal n_flushes, wire_bytes
            params, values = pending
            self._publish_values_flush(params, values, is_last=is_last, verify=verify)
            n_flushes += 1
            wire_bytes += int(values.nbytes)

        bkt = _FlushBucket(self.bucket_size, _assemble_values, _publish_values)

        seen_names: set = set()
        for name, tensor in weights:
            # duplicate names in a full export mean two source params mapped to
            # the same HF tensor -- the receiver would apply whichever came last
            # and the delta diff base would silently disagree with the trainer
            # (observed: NemotronH A_log). Fail loud instead.
            assert name not in seen_names, f"full export yields duplicate HF tensor {name!r}"
            seen_names.add(name)
            tensor = tensor.detach()
            if tensor.is_floating_point() and tensor.dtype != self.rollout_dtype:
                tensor = tensor.to(self.rollout_dtype)
            if not is_r0:
                del tensor
                continue
            flat = tensor.contiguous().reshape(-1)
            total_elems += int(flat.numel())
            bkt.add(_ValuesPiece(name, str(flat.dtype).replace("torch.", ""), list(tensor.shape), flat), flat.nbytes)

        if not is_r0:
            return
        bkt.seal()
        if bkt.pending is not None:
            bkt.emit(is_last=True)
        else:
            self._publish_terminal(True)
        self._release_after_round("seed")
        logger.info(
            "delta-sharded FULL-%s v=%s done in %.1fs (flushes=%d elems=%d wire=%.1fGB)",
            "VERIFY" if verify else "SEED",
            global_steps,
            time.time() - t0,
            n_flushes,
            total_elems,
            wire_bytes / (1 << 30),
        )
        if not total_elems:
            return None
        return {
            "checkpoint_engine/changed_ratio": 1.0,
            "checkpoint_engine/changed_elems": float(total_elems),
            "checkpoint_engine/payload_mbytes": wire_bytes / (1 << 20),
            "checkpoint_engine/flushes": float(n_flushes),
        }

    async def send_weights(
        self,
        engine,
        global_steps: int | None = None,
    ) -> dict[str, float] | None:
        """Drive one weight sync from the TRAINING ENGINE (unlike the full-sync
        engines, which consume a weights iterator): the seed/steady phase choice
        and the snapshot prime are this engine's own state machine, so the worker
        stays delta-agnostic. The seed (first sync) streams the backend's full
        ``get_per_tensor_param()`` export over the values-only wire, then pins the
        diff base via ``engine.prime_delta_snapshots()``; every later sync consumes
        ``get_per_tensor_param_delta_shard()`` (backend-computed final-HF deltas).
        """
        # All actor ranks participate (gather-v is collective); only torch rank 0 broadcasts.
        # rank 0 accumulates the gathered per-param deltas into bucket_size-sized flushes and streams
        # each one as soon as it fills (then frees it), so peak memory is ~2 buckets rather than the
        # whole model.
        assert self.rank <= 0, "Trainer workers other than rank 0 should not send weights."
        if not self._shard_seeded:
            full, _ = engine.get_per_tensor_param()
            metrics = self._send_full_seed(full, global_steps)
            # weights do not move during the sync, so the snapshots equal exactly
            # what the rollout just received.
            engine.prime_delta_snapshots()
            # The seed is complete only after its baseline snapshots are ready.
            self._shard_seeded = True
            return metrics
        weights, _ = engine.get_per_tensor_param_delta_shard()
        is_r0 = self.is_master
        n_flushes = 0
        changed_elems = 0
        total_elems = 0
        wire_bytes = 0

        def _publish_steady(flush, is_last: bool) -> None:
            nonlocal n_flushes
            self._publish_flush(flush, first=False, is_last=is_last)
            n_flushes += 1

        bkt = _FlushBucket(self.bucket_size, self._assemble_flush, _publish_steady)

        batch_k = self.batch_gather

        def _bucket_slot_delta(
            name: str,
            dtype_str: str,
            full_shape: tuple,
            full_numel: int,
            aidx: torch.Tensor | None,
            aval: torch.Tensor | None,
        ) -> None:
            nonlocal total_elems, changed_elems, wire_bytes
            total_elems += int(full_numel)
            if aidx is None or aidx.numel() == 0:
                return
            changed_elems += int(aidx.numel())
            wire_bytes += int(aidx.numel()) * (4 + aval.element_size())
            _bucket_sliced(bkt, name, dtype_str, full_shape, aidx, aval)

        gq = _GatherQueue(batch_k, self.bucket_size, is_r0, _bucket_slot_delta)

        # ``weights`` is the BACKEND's HF delta stream (hf_delta_export): entries
        # already carry final HF coordinates -- naming, conversion, diff and
        # snapshot all happened on the backend side. This engine only batches,
        # gathers and ships.
        for slots, dtype_str, counts, hf_idx, hf_val, pg in weights:
            gq.put(pg, slots, dtype_str, counts, hf_idx, hf_val)
        gq.flush_all()

        # For SGLang, verify_every=K appends a dense state-verification sweep to
        # every K-th steady sync inside the same receive stream. The steady bucket
        # keeps ``is_last`` unset, and the sweep's final flush carries it. The
        # receiver bit-compares each destination before overwriting it and fails
        # on any mismatch (see delta_loader._verify_dense).
        verify = self._verify_due()
        if is_r0:
            bkt.seal()  # seal the final partial bucket into the pending flush
            if bkt.pending is not None:
                bkt.emit(is_last=not verify)
            elif not verify:
                self._publish_terminal(False)
        if verify:
            # collective on every rank: the full export assembles per tensor.
            full, _ = engine.get_per_tensor_param()
            self._send_full_seed(full, global_steps, verify=True)
        if not is_r0:
            return
        self._release_after_round("steady")
        logger.info("delta-sharded send v=%s delta flushes=%d (streamed)", global_steps, n_flushes)
        if not total_elems:
            return None
        return {
            "checkpoint_engine/changed_ratio": changed_elems / total_elems,
            "checkpoint_engine/changed_elems": float(changed_elems),
            "checkpoint_engine/payload_mbytes": wire_bytes / (1 << 20),
            "checkpoint_engine/flushes": float(n_flushes),
        }
