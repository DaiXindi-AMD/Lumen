###############################################################################
# Copyright (c) 2025, Advanced Micro Devices, Inc. All rights reserved.
#
# Licensed under the Apache License, Version 2.0
###############################################################################

"""Megatron-compatible fused MoE router ops.

Three ``torch.autograd.Function`` wrappers matching Megatron-Core's
``moe_utils`` fused-router surface:

1. ``fused_topk_with_score_function``
2. ``fused_compute_score_for_moe_aux_loss``
3. ``fused_moe_aux_loss``

Token permute / unpermute live in :mod:`lumen.ops.moe.fused_routing`.
AITER HIP ``softmax_topk`` is preferred; PyTorch softmax+topk is used when
the probe fails (CPU, or a build without that binding).
"""

from __future__ import annotations

import logging
from typing import Optional, Tuple

import torch
from torch import Tensor

from lumen.ops.dispatch import (
    _probe_aiter_softmax_topk,
    _probe_aiter_triton_moe_aux_loss,
)

logger = logging.getLogger(__name__)


def _aiter_softmax_topk(logits_fp32: Tensor, k: int, need_renorm: bool):
    """Call AITER HIP softmax_topk, allocating output buffers."""
    N, E = logits_fp32.shape
    device = logits_fp32.device
    scores = torch.empty(N, E, dtype=torch.float32, device=device)
    topk_weights = torch.empty(N, k, dtype=torch.float32, device=device)
    topk_indices = torch.empty(N, k, dtype=torch.int32, device=device)
    token_expert_indices = torch.empty(N, k, dtype=torch.int32, device=device)

    from aiter.ops.moe_op import softmax_topk

    softmax_topk(
        scores,
        topk_weights,
        topk_indices,
        token_expert_indices,
        logits_fp32.contiguous(),
        k,
        need_renorm,
    )
    return scores, topk_weights, topk_indices


def _pytorch_softmax_topk(logits_fp32: Tensor, k: int, need_renorm: bool):
    """Pure PyTorch fallback for softmax + topk."""
    scores = torch.softmax(logits_fp32, dim=-1)
    topk_weights, topk_indices = scores.topk(k, dim=-1, largest=True, sorted=True)
    if need_renorm:
        topk_weights = topk_weights / topk_weights.sum(dim=-1, keepdim=True)
    return scores, topk_weights, topk_indices


def _softmax_topk(logits_fp32: Tensor, k: int, need_renorm: bool):
    if _probe_aiter_softmax_topk():
        return _aiter_softmax_topk(logits_fp32, k, need_renorm)
    # HIP binding is absent on CPU and on AITER builds without moe_op.softmax_topk.
    logger.debug("fused_router: AITER softmax_topk unavailable, using PyTorch softmax+topk")
    return _pytorch_softmax_topk(logits_fp32, k, need_renorm)


class LumenFusedComputeScoreForMoEAuxLoss(torch.autograd.Function):
    @staticmethod
    def forward(ctx, logits: Tensor, topk: int) -> Tuple[Tensor, Tensor]:
        logits_fp32 = logits.float()
        scores, _, topk_indices = _softmax_topk(logits_fp32, topk, False)

        N, E = scores.shape
        routing_map = torch.zeros(N, E, dtype=torch.bool, device=logits.device)
        routing_map.scatter_(1, topk_indices.long(), True)

        ctx.save_for_backward(scores)

        return routing_map, scores

    @staticmethod
    def backward(ctx, grad_routing_map, grad_scores):
        (scores,) = ctx.saved_tensors
        dot = (grad_scores * scores).sum(dim=-1, keepdim=True)
        grad_logits = scores * (grad_scores - dot)
        return grad_logits, None


class LumenFusedTopkWithScoreFunction(torch.autograd.Function):
    @staticmethod
    def forward(
        ctx,
        logits: Tensor,
        topk: int,
        use_pre_softmax: bool,
        scaling_factor: Optional[float],
    ) -> Tuple[Tensor, Tensor]:
        N, E = logits.shape

        if use_pre_softmax:
            logits_fp32 = logits.float()
            s, w, topk_indices = _softmax_topk(logits_fp32, topk, True)

            s_k = s.gather(1, topk_indices.long())
            V = s_k.sum(dim=-1, keepdim=True)

            if scaling_factor is not None:
                w = w * scaling_factor

            routing_probs = torch.zeros(N, E, dtype=w.dtype, device=logits.device)
            routing_probs.scatter_(1, topk_indices.long(), w)

            routing_map = torch.zeros(N, E, dtype=torch.bool, device=logits.device)
            routing_map.scatter_(1, topk_indices.long(), True)

            ctx.save_for_backward(s, s_k, topk_indices.long(), V)
            ctx.scaling_factor = scaling_factor
            ctx.use_pre_softmax = True

            return routing_map, routing_probs

        else:
            ctx.use_pre_softmax = False
            logits_fp32 = logits.float().detach().requires_grad_(True)
            with torch.enable_grad():
                _, topk_indices = logits_fp32.topk(topk, dim=-1)
                gathered = logits_fp32.gather(1, topk_indices)
                w = torch.softmax(gathered, dim=-1)

                if scaling_factor is not None:
                    w = w * scaling_factor

                routing_probs = torch.zeros(N, E, dtype=w.dtype, device=logits.device)
                routing_probs.scatter_(1, topk_indices, w)

            routing_map = torch.zeros(N, E, dtype=torch.bool, device=logits.device)
            routing_map.scatter_(1, topk_indices, True)

            ctx.save_for_backward(logits_fp32, routing_probs)
            ctx._pre_softmax_false_graph = routing_probs

            return routing_map, routing_probs.detach()

    @staticmethod
    def backward(ctx, grad_routing_map, grad_routing_probs):
        if ctx.use_pre_softmax:
            s, s_k, topk_indices, V = ctx.saved_tensors
            N, E = s.shape

            grad_w = grad_routing_probs.gather(1, topk_indices)

            if ctx.scaling_factor is not None:
                grad_w = grad_w * ctx.scaling_factor

            w = s_k / V
            grad_s_k = (grad_w - (grad_w * w).sum(dim=-1, keepdim=True)) / V

            grad_s = torch.zeros(N, E, dtype=s.dtype, device=s.device)
            grad_s.scatter_add_(1, topk_indices, grad_s_k)

            dot = (grad_s * s).sum(dim=-1, keepdim=True)
            grad_logits = s * (grad_s - dot)

            return grad_logits, None, None, None

        else:
            logits_fp32, routing_probs = ctx.saved_tensors
            routing_probs.backward(grad_routing_probs)
            return logits_fp32.grad, None, None, None


class LumenFusedMoEAuxLoss(torch.autograd.Function):
    @staticmethod
    def forward(
        ctx,
        probs: Tensor,
        tokens_per_expert: Tensor,
        total_num_tokens: int,
        num_experts: int,
        topk: int,
        coeff: float,
    ) -> Tensor:
        C = num_experts * coeff / (topk * total_num_tokens * total_num_tokens)
        ctx.save_for_backward(tokens_per_expert)
        ctx.C = C
        ctx.N = probs.shape[0]
        ctx.E = num_experts

        if _probe_aiter_triton_moe_aux_loss():
            from aiter.ops.triton.moe.moe_aux_loss import moe_aux_loss_fwd

            return moe_aux_loss_fwd(probs.float(), tokens_per_expert.float(), C)
        # Triton aux-loss kernels are gfx-specific; the Switch LB formula is
        # a reduction over (probs, tokens_per_expert) and is exact in PyTorch.
        logger.debug("fused_router: AITER moe_aux_loss unavailable, using PyTorch Switch LB")
        aggregated = probs.float().sum(dim=0)
        return (aggregated * tokens_per_expert.float()).sum() * C

    @staticmethod
    def backward(ctx, grad_aux_loss: Tensor):
        (tokens_per_expert,) = ctx.saved_tensors

        if _probe_aiter_triton_moe_aux_loss():
            from aiter.ops.triton.moe.moe_aux_loss import moe_aux_loss_bwd

            grad_probs = moe_aux_loss_bwd(tokens_per_expert.float(), ctx.C, grad_aux_loss, ctx.N, ctx.E)
        else:
            logger.debug("fused_router: AITER moe_aux_loss_bwd unavailable, using PyTorch Switch LB grad")
            grad_probs = tokens_per_expert.float().unsqueeze(0).expand(ctx.N, ctx.E) * ctx.C * grad_aux_loss

        return grad_probs, None, None, None, None, None


def fused_topk_with_score_function(
    logits: Tensor,
    topk: int,
    use_pre_softmax: bool,
    num_groups: Optional[int],
    group_topk: Optional[int],
    scaling_factor: Optional[float],
    score_function: str,
    expert_bias: Optional[Tensor],
) -> Tuple[Tensor, Tensor]:
    if score_function != "softmax":
        raise NotImplementedError(f"score_function='{score_function}' not supported, only 'softmax'")
    if num_groups and num_groups > 0:
        raise NotImplementedError("Group routing (num_groups > 0) not supported")
    if group_topk and group_topk > 0:
        raise NotImplementedError("Group top-k not supported")
    if expert_bias is not None:
        raise NotImplementedError("expert_bias not supported")

    return LumenFusedTopkWithScoreFunction.apply(logits, topk, use_pre_softmax, scaling_factor)


def fused_compute_score_for_moe_aux_loss(
    logits: Tensor,
    topk: int,
    score_function: str,
) -> Tuple[Tensor, Tensor]:
    if score_function != "softmax":
        raise NotImplementedError(f"score_function='{score_function}' not supported, only 'softmax'")
    return LumenFusedComputeScoreForMoEAuxLoss.apply(logits, topk)


def fused_moe_aux_loss(
    probs: Tensor,
    tokens_per_expert: Tensor,
    total_num_tokens: int,
    num_experts: int,
    topk: int,
    coeff: float,
) -> Tensor:
    return LumenFusedMoEAuxLoss.apply(probs, tokens_per_expert, total_num_tokens, num_experts, topk, coeff)
