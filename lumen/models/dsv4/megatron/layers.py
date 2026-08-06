"""Megatron-compatible linear/norm modules without Transformer Engine."""

from __future__ import annotations

from typing import Callable, Optional

import torch
import torch.nn as nn
import torch.nn.functional as F
from megatron.core.tensor_parallel.layers import (
    set_tensor_model_parallel_attributes,
)
from megatron.core.transformer.module import MegatronModule

from lumen.modules.parallel_linear import LumenColumnParallelLinear, LumenRowParallelLinear


class LumenNorm(torch.nn.Module):
    """Megatron-compatible RMSNorm/LayerNorm without Transformer Engine."""

    def __init__(self, config, hidden_size, eps=1e-6, **kwargs):
        super().__init__()
        del kwargs
        norm_type = getattr(config, "normalization", "LayerNorm")
        if norm_type == "RMSNorm":
            from lumen.ops.normalization import LumenRMSNorm

            self._norm = LumenRMSNorm(hidden_size, eps=eps)
        else:
            from lumen.ops.normalization import LumenLayerNorm

            self._norm = LumenLayerNorm(hidden_size, eps=eps)
        self.weight = self._norm.weight

    def forward(self, x):
        return self._norm(x)

__all__ = [
    "LumenDuplicatedLinear",
    "LumenColumnParallelLinear",
    "LumenRowParallelLinear",
    "LumenNorm",
]


class LumenDuplicatedLinear(MegatronModule):
    """BF16 linear duplicated on every TP rank (TE ``parallel_mode='duplicated'`` replacement)."""

    def __init__(
        self,
        input_size: int,
        output_size: int,
        *,
        config,
        init_method: Callable,
        bias: bool = False,
        skip_bias_add: bool = False,
        skip_weight_param_allocation: bool = False,
        parallel_mode: Optional[str] = "duplicated",
        is_expert: bool = False,
        tp_group=None,
        tp_comm_buffer_name: Optional[str] = None,
        **kwargs,
    ):
        super().__init__(config=config)
        del parallel_mode, is_expert, tp_group, tp_comm_buffer_name, kwargs
        if skip_weight_param_allocation:
            raise ValueError("LumenDuplicatedLinear does not support skip_weight_param_allocation")

        self.input_size = input_size
        self.output_size = output_size
        self.skip_bias_add = skip_bias_add

        self.scaling_type = "none"
        self.scaling_manager = None
        from lumen.quantize.config import _get_float8_e4m3

        self.fp8_dtype = _get_float8_e4m3()
        self.block_size = 128

        self.weight = nn.Parameter(torch.empty(output_size, input_size, dtype=config.params_dtype))
        set_tensor_model_parallel_attributes(self.weight, True, 0, 1)
        if bias:
            self.bias = nn.Parameter(torch.empty(output_size, dtype=config.params_dtype))
        else:
            self.register_parameter("bias", None)

        if config.perform_initialization:
            init_method(self.weight)
            if self.bias is not None:
                with torch.no_grad():
                    self.bias.zero_()

    def forward(self, x: torch.Tensor):
        bias = None if self.skip_bias_add else self.bias
        if self.scaling_type != "none":
            from lumen.ops.quantize.linear import quantized_linear

            out = quantized_linear(
                x,
                self.weight,
                bias,
                scaling_manager=self.scaling_manager,
                scaling_type=self.scaling_type,
                fp8_dtype=self.fp8_dtype,
                block_size=self.block_size,
            )
        else:
            out = F.linear(x, self.weight, bias)
        output_bias = self.bias if self.skip_bias_add and self.bias is not None else None
        return out, output_bias

    def enable_fp8(self, scaling_manager=None, scaling_type="dynamic", fp8_dtype=None, block_size=None):
        from lumen.quantize import QuantConfig, ScalingManager

        self.scaling_type = scaling_type
        self.scaling_manager = scaling_manager or ScalingManager(QuantConfig())
        if fp8_dtype is not None:
            self.fp8_dtype = fp8_dtype
        if block_size is not None:
            self.block_size = block_size
