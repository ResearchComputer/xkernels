# SPDX-License-Identifier: MIT
# Copyright (c) 2026 ResearchComputer
"""moe_align_block_size (issue #4): sort/pad routed tokens into per-expert blocks.

The fused-MoE block GEMM needs tokens grouped by expert with each expert's run
padded to a multiple of ``block_size``, so every block maps to exactly one
expert. This exposes the operation as a dispatched op over the correctness-first
torch reference (``moe_align_block_size_ref``, REFERENCE) and a Triton perf
backend (TRITON).

**Backends:** the REFERENCE is an argsort + per-expert torch padding loop; the
TRITON backend (``align_kernel.moe_align_block_size_triton``) is the vLLM/SGLang
-style 4-stage histogram + padded prefix-sum + scatter, validated bit-for-bit
against the reference (GPU, or CPU under ``TRITON_INTERPRET=1``). ``auto`` picks
TRITON on GPU vendors and falls back to REFERENCE on CPU-only builds.
"""

from __future__ import annotations

import torch

from ..._backends import Backend
from ..._dispatch import dispatch, register
from .w4a16 import moe_align_block_size_ref

__all__ = ["moe_align_block_size"]

# The reference (in w4a16.py, shared with the INT4 GEMM launcher) is the oracle.
# The TRITON backend (bit-for-bit identical) self-registers from
# triton/align_kernel.py, imported for its side effect by ops/moe/__init__.py.
register("moe_align_block_size", Backend.REFERENCE)(moe_align_block_size_ref)


def moe_align_block_size(
    topk_ids: torch.Tensor,
    block_size: int,
    num_experts: int,
    *,
    backend: Backend | str = "auto",
    truncate: bool = True,
    workspace=None,
) -> tuple[torch.Tensor, torch.Tensor, torch.Tensor]:
    """Sort/pad routed token-slots into per-expert blocks.

    Args:
        topk_ids: ``[M, top_k]`` int32 expert id per token-slot.
        block_size: GEMM block size each expert run is padded up to.
        num_experts: number of experts.
        backend: ``"auto"`` or a ``Backend`` / its string value.
        truncate: if True (default) trim ``expert_ids`` to used blocks (eager); if
            False return the full ``max_blocks`` length with no host sync, for
            HIP/CUDA-graph capture (Triton backend).
        workspace: optional :class:`~xkernels.ops.moe.workspace.MoeAlignWorkspace`
            (issue #52). The Triton backend re-inits the five scratch buffers
            IN PLACE into the workspace (fill ``sorted_ids`` with ``pad_id``, zero
            the rest) so the buffer ADDRESSES are stable across calls -- the
            precondition for CUDA/HIP graph capture. The init cost is unchanged
            (these are counters, not fully-overwritten); the win is address
            stability. Ignored by the reference backend. ``None`` (default) =
            allocate-each-call.

    Returns:
        ``(sorted_token_ids [max_pad], expert_ids [max_blocks], num_tokens_post_padded [1])``
        where ``max_pad = M*top_k + (num_experts+1)*(block_size-1)`` and unused
        slots hold ``pad_id = M*top_k``.
    """
    return dispatch(
        "moe_align_block_size", topk_ids, block_size, num_experts,
        backend=backend, truncate=truncate, workspace=workspace,
    )
