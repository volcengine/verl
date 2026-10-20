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


import torch
import torch.nn.functional as F

from verl.trainer.distillation.tail_kl import compute_tail_bucket_kl
from verl.utils.ulysses import (
    get_ulysses_sequence_parallel_world_size,
    slice_input_tensor,
)
from verl.workers.config import DistillationConfig, DistillationLossConfig


def _chunked_topk_log_probs(
    logits: torch.Tensor,
    topk_ids: torch.Tensor,
    chunk_size: int = 4096,
) -> torch.Tensor:
    """Compute log_softmax(logits).gather(topk_ids) without materializing [B, T, V].

    Uses the identity:
        log_softmax(x).gather(idx) == x.gather(idx) - logsumexp(x, keepdim=True)
    Streams the reduction in chunks of `chunk_size` tokens along (B*T) with fp32
    logsumexp for numerical stability.

    Args:
        logits:    [B, T, V] student logits.
        topk_ids:  [B, T, K] indices to gather.
        chunk_size: number of tokens per chunk; only affects memory, not numerics.

    Returns:
        [B, T, K] tensor with the same dtype as `logits`.
    """
    B, T, V = logits.shape
    K = topk_ids.shape[-1]
    flat_logits = logits.reshape(-1, V)  # [N, V]
    flat_topk = topk_ids.reshape(-1, K)  # [N, K]
    N = flat_logits.shape[0]

    # Edge case: empty input (e.g. fully-padded micro-batch).
    if N == 0:
        return torch.empty((B, T, K), dtype=logits.dtype, device=logits.device)

    out = torch.empty((N, K), dtype=logits.dtype, device=logits.device)
    for s in range(0, N, chunk_size):
        e = min(s + chunk_size, N)
        chunk_logits_fp32 = flat_logits[s:e].float()
        log_z = torch.logsumexp(chunk_logits_fp32, dim=-1, keepdim=True)  # [c, 1]
        chunk_topk_logits = torch.gather(chunk_logits_fp32, dim=-1, index=flat_topk[s:e])
        out[s:e] = (chunk_topk_logits - log_z).to(logits.dtype)
    return out.reshape(B, T, K)


def kl_divergence(log_q: torch.Tensor, log_p: torch.Tensor) -> torch.Tensor:
    """Compute KL divergence between two distributions given their log probabilities."""
    log_p = log_p.float()
    log_q = log_q.float()
    p = log_p.exp()
    kld = p * (log_p - log_q)
    return kld.sum(dim=-1)


def tail_aware_kl_divergence(
    log_q: torch.Tensor,
    log_p: torch.Tensor,
    tail_mass_eps: float,
) -> tuple[torch.Tensor, torch.Tensor, torch.Tensor, torch.Tensor]:
    """Compute forward KL after collapsing all non-top-k tokens into one tail bucket.

    ``log_p`` and ``log_q`` contain probabilities on the teacher-selected top-k
    support. The returned divergence is the exact KL between the two
    ``K + 1``-class distributions ``[p_topk, 1 - p_topk.sum()]`` and
    ``[q_topk, 1 - q_topk.sum()]``.

    Related work:
        - Decoupled Top-K Knowledge Distillation in the LFM2 Technical Report:
          https://arxiv.org/abs/2511.23404v1
          At temperature 1, its Bernoulli membership KL plus the teacher-mass-weighted
          conditional Top-k KL are algebraically the same objective computed here.
        - Ghost token in Sparse Logit Sampling: Accelerating Knowledge Distillation in LLMs:
          https://aclanthology.org/2025.acl-long.885.pdf

    Returns:
        A tuple of per-token coarse-grained divergence, student top-k mass,
        teacher top-k mass, and the tail-bucket contribution. The divergence
        is ``topk_loss + tail_loss``.
    """
    log_p = log_p.float()
    log_q = log_q.float()
    p = log_p.exp()
    q = log_q.exp()

    teacher_mass = p.sum(dim=-1)
    student_mass = q.sum(dim=-1)
    topk_loss = (p * (log_p - log_q)).sum(dim=-1)
    tail_loss = compute_tail_bucket_kl(
        student_topk_mass=student_mass,
        teacher_topk_mass=teacher_mass,
        tail_mass_eps=tail_mass_eps,
    )
    return topk_loss + tail_loss, student_mass, teacher_mass, tail_loss


def compute_forward_kl_topk(
    student_logits: torch.Tensor,
    teacher_topk_log_probs: torch.Tensor,
    teacher_topk_ids: torch.Tensor,
    config: DistillationConfig,
    data_format: str,
    *,
    include_tail: bool = False,
) -> dict[str, torch.Tensor]:
    """Compute truncated or tail-aware teacher-top-k KL with the FSDP backend.

    Args:
        student_logits: (bsz, seqlen/sp_size, vocab_size).
        teacher_topk_log_probs: (bsz, seqlen, topk).
        teacher_topk_ids: (bsz, seqlen, topk).
        config: distillation config, providing ``log_prob_min_clamp`` and ``tail_mass_eps``.
        data_format: "thd" or "bshd", models not support THD format, e.g GPT-OSS, Qwen3.5
        include_tail: whether to collapse all non-top-k tokens into one aggregate
            bucket, which turns the truncated objective into the exact forward KL
            between the two coarse-grained ``K + 1``-class distributions.
            Selected by ``loss_mode=forward_kl_topk_tail``.

    Returns:
    - distillation_losses: (bsz, seqlen/sp_size)
    - student_mass: (bsz, seqlen/sp_size)
    - teacher_mass: (bsz, seqlen/sp_size)
    - tail_loss: (bsz, seqlen/sp_size), only when ``include_tail=True``
    """
    assert teacher_topk_log_probs.is_nested and teacher_topk_ids.is_nested
    teacher_topk_log_probs = teacher_topk_log_probs.values().unsqueeze(0)  # (1, total_nnz, topk)
    teacher_topk_ids = teacher_topk_ids.values().unsqueeze(0)  # (1, total_nnz, topk)

    # 1. split across sp groups (bsz, seqlen, topk) => (bsz, seqlen/sp_size, topk)
    if get_ulysses_sequence_parallel_world_size() > 1:
        teacher_topk_log_probs = slice_input_tensor(teacher_topk_log_probs, dim=1)
        teacher_topk_ids = slice_input_tensor(teacher_topk_ids, dim=1)
    assert teacher_topk_log_probs.shape[:2] == teacher_topk_ids.shape[:2] == student_logits.shape[:2]

    # 2. compute token-wise KL divergence across sp groups
    # ``use_chunked_topk`` (opt-in, default off) trades latency for memory:
    # the chunked path streams logsumexp + gather to avoid the [B, T, V]
    # log_softmax buffer, enabling long-context (>=64K) where the default
    # F.log_softmax path OOMs. See ``DistillationLossConfig.use_chunked_topk``
    # for trade-offs and benchmark numbers.
    loss_config: DistillationLossConfig = config.distillation_loss
    use_chunked_topk = getattr(loss_config, "use_chunked_topk", False)
    if use_chunked_topk:
        # log_softmax is monotonic, so topk(logits) == topk(log_softmax(logits)).
        student_topk_ids = torch.topk(student_logits, k=teacher_topk_ids.shape[-1], dim=-1).indices
        student_topk_log_probs = _chunked_topk_log_probs(
            student_logits,
            teacher_topk_ids,
            chunk_size=getattr(loss_config, "chunked_topk_chunk_size", 4096),
        )
    else:
        student_log_probs = F.log_softmax(student_logits, dim=-1)
        student_topk_ids = torch.topk(student_log_probs, k=teacher_topk_ids.shape[-1], dim=-1).indices
        student_topk_log_probs = torch.gather(student_log_probs, dim=-1, index=teacher_topk_ids)

    tail_loss = None
    if include_tail:
        distillation_losses, student_mass, teacher_mass, tail_loss = tail_aware_kl_divergence(
            log_q=student_topk_log_probs,
            log_p=teacher_topk_log_probs,
            tail_mass_eps=loss_config.tail_mass_eps,
        )
    else:
        student_mass = student_topk_log_probs.exp().sum(dim=-1)
        teacher_mass = teacher_topk_log_probs.exp().sum(dim=-1)
        if loss_config.log_prob_min_clamp is not None:
            student_topk_log_probs = student_topk_log_probs.clamp_min(loss_config.log_prob_min_clamp)
            teacher_topk_log_probs = teacher_topk_log_probs.clamp_min(loss_config.log_prob_min_clamp)
        distillation_losses = kl_divergence(log_q=student_topk_log_probs, log_p=teacher_topk_log_probs)

    # Diagnostics for tracking teacher/student top-k overlap in OPD, following
    # "Rethinking On-Policy Distillation of Large Language Models" (arXiv:2604.13016).
    overlap_mask = (teacher_topk_ids.unsqueeze(-1) == student_topk_ids.unsqueeze(-2)).any(dim=-1)
    overlap_count = overlap_mask.sum(dim=-1)
    token_kl = teacher_topk_log_probs.float().exp() * (teacher_topk_log_probs.float() - student_topk_log_probs.float())
    overlap_token_advantage_sum = (-token_kl * overlap_mask).sum(dim=-1)
    overlap_token_advantage = overlap_token_advantage_sum / overlap_count.clamp_min(1)
    overlap_token_advantage = torch.where(
        overlap_count > 0, overlap_token_advantage, torch.zeros_like(overlap_token_advantage)
    )

    outputs = {
        "distillation_losses": distillation_losses,
        "student_mass": student_mass,
        "teacher_mass": teacher_mass,
        "overlap_count": overlap_count,
        "overlap_token_advantage": overlap_token_advantage,
    }
    if tail_loss is not None:
        outputs["tail_loss"] = tail_loss
    return outputs
