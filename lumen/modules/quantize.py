###############################################################################
# Copyright (c) 2025, Advanced Micro Devices, Inc. All rights reserved.
#
# See LICENSE for license information.
###############################################################################

"""nn.Module wrappers for quantized linear — mirrors ``attention.py``'s
:class:`LumenAttention`.

Usage::

    from lumen.modules import LumenLinear

    linear = LumenLinear(
        in_features=4096,
        out_features=4096,
        backend_type="aiter",        # or "triton"
    )
    output = linear(x)               # FP8 quant/dequant handled internally
"""

from typing import Literal, Optional

import torch
import torch.nn as nn

from lumen.quantize import ScalingManager, QuantConfig, is_aiter_available
from lumen.ops.quantize import quantized_linear

__all__ = ["LumenLinear"]


class LumenLinear(nn.Module):
    """Drop-in replacement for ``nn.Linear`` with FP8 quantized forward + backward.

    Supports AITER (hipBLASLt) and Triton (blockwise) backends, mirroring
    :class:`~lumen.modules.attention.LumenAttention`.

    Args:
        in_features: Size of each input sample.
        out_features: Size of each output sample.
        bias: If ``True``, adds a learnable bias. Default: ``True``.
        backend_type: ``"aiter"`` or ``"triton"``.
        fp8_dtype: Target FP8 dtype. Default: ``torch.float8_e4m3fn``.
        block_size: Block size for blockwise quantization (triton backend).
        config: Optional :class:`~lumen.quantize.QuantConfig`.
                If not provided, a default config is created.
    """

    def __init__(
        self,
        in_features: int,
        out_features: int,
        bias: bool = True,
        backend_type: str = "aiter",
        fp8_dtype: torch.dtype = torch.float8_e4m3fn,
        block_size: int = 128,
        config: Optional[QuantConfig] = None,
    ):
        super().__init__()

        if backend_type == "aiter" and not is_aiter_available():
            raise RuntimeError(
                "AITER is not installed. The aiter backend requires "
                "'aiter' — install it or use backend_type='triton'."
            )

        self.in_features = in_features
        self.out_features = out_features
        self.backend_type = backend_type
        self.fp8_dtype = fp8_dtype
        self.block_size = block_size

        self.weight = nn.Parameter(torch.empty(out_features, in_features))
        if bias:
            self.bias = nn.Parameter(torch.zeros(out_features))
        else:
            self.register_parameter("bias", None)

        self.scaling_manager = ScalingManager(config or QuantConfig())

        self.reset_parameters()

    def reset_parameters(self):
        nn.init.kaiming_uniform_(self.weight)
        if self.bias is not None:
            nn.init.zeros_(self.bias)

    def forward(self, input: torch.Tensor) -> torch.Tensor:
        return quantized_linear(
            input,
            self.weight,
            self.bias,
            scaling_manager=self.scaling_manager,
            backend=self.backend_type,
            fp8_dtype=self.fp8_dtype,
            block_size=self.block_size,
        )

    def extra_repr(self) -> str:
        return (
            f"in_features={self.in_features}, out_features={self.out_features}, "
            f"bias={self.bias is not None}, backend={self.backend_type}, "
            f"fp8_dtype={self.fp8_dtype}, block_size={self.block_size}"
        )
