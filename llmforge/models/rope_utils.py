# Copyright © 2023-2024 Apple Inc.

import math
from typing import List, Optional, Union

import torch
import torch.nn as nn


class RoPE(nn.Module):
    """Standard Rotary Positional Embedding."""

    def __init__(
        self,
        dims: int,
        traditional: bool = False,
        base: float = 10000.0,
        scale: float = 1.0,
    ):
        super().__init__()
        self.dims = dims
        self.traditional = traditional
        self.scale = scale
        self.base = base
        # Transformers convention: inv_freq = 1 / base^(i/dim)
        freqs = 1.0 / (base ** (torch.arange(0, dims, 2, dtype=torch.float32) / dims))
        self.register_buffer("_freqs", freqs, persistent=False)

    def _compute_rope(self, x, offset=0, freqs=None):
        if freqs is None:
            freqs = self._freqs
        # Handle both 3D (B, L, D) and 4D (B, H, L, D) inputs
        orig_shape = x.shape
        if x.dim() == 4:
            B, H, L, D = x.shape
            x = x.reshape(B * H, L, D)
        else:
            B, L, _ = x.shape
        positions = torch.arange(
            offset, offset + L, dtype=torch.float32, device=x.device
        )
        angles = torch.outer(positions, freqs)
        cos = torch.cos(angles) * self.scale
        sin = torch.sin(angles) * self.scale

        if self.traditional:
            # Traditional MLX-style: split half, unique freq per pair
            x1 = x[..., : self.dims // 2]
            x2 = x[..., self.dims // 2 : self.dims]
            rx1 = x1 * cos - x2 * sin
            rx2 = x1 * sin + x2 * cos
            result = torch.cat([rx1, rx2], dim=-1)
        else:
            # Transformers-style: split half, same freq for both halves
            # cos_full = [cos, cos] (repeat the full 64-value sequence twice)
            cos_d = cos.repeat(1, 2) if cos.dim() > 1 else cos.repeat(2)
            sin_d = sin.repeat(1, 2) if sin.dim() > 1 else sin.repeat(2)
            half = self.dims // 2
            x1 = x[..., :half]
            x2 = x[..., half:]
            rx1 = x1 * cos_d[..., :half] - x2 * sin_d[..., :half]
            rx2 = x2 * cos_d[..., half:] + x1 * sin_d[..., half:]
            result = torch.cat([rx1, rx2], dim=-1)

        if len(orig_shape) == 4:
            result = result.reshape(orig_shape)
        return result

    def forward(self, x, offset: Union[int, torch.Tensor] = 0, freqs=None):
        if isinstance(offset, torch.Tensor):
            offset = offset.item() if offset.numel() == 1 else offset
        return self._compute_rope(x, offset, freqs=freqs)


class SuScaledRoPE(nn.Module):
    def __init__(
        self,
        dims: int,
        base: float = 10000.0,
        max_position_embeddings: int = 131072,
        original_max_position_embeddings: int = 4096,
        short_factor: Union[List[float], float] = 1.0,
        long_factor: Union[List[float], float] = 1.0,
        short_mscale: float = None,
        long_mscale: float = None,
    ):
        super().__init__()
        self.original_max_position_embeddings = original_max_position_embeddings
        self.dim = dims

        freqs = base ** (torch.arange(0, dims, 2, dtype=torch.float32) / dims)
        self._freqs = torch.tensor(long_factor, dtype=torch.float32) * freqs

        def default_scale(factor):
            return math.sqrt(
                1 + math.log(factor) / math.log(original_max_position_embeddings)
            )

        factor = max_position_embeddings / original_max_position_embeddings
        self._scale = long_mscale or (1.0 if factor <= 1.0 else default_scale(factor))

    def forward(self, x, offset: Union[int, torch.Tensor] = 0):
        if isinstance(offset, torch.Tensor):
            offset = offset.item() if offset.numel() == 1 else offset
        x = x.clone()
        x[..., : self.dim] = self._scale * x[..., : self.dim]
        return self._apply_rope(x, offset)

    def _apply_rope(self, x, offset):
        freqs = self._freqs.to(x.device)
        positions = torch.arange(
            offset, offset + x.shape[1], dtype=torch.float32, device=x.device
        )
        angles = torch.outer(positions, freqs)
        cos = torch.cos(angles)
        sin = torch.sin(angles)
        x1 = x[..., : self.dim // 2]
        x2 = x[..., self.dim // 2 : self.dim]
        rx1 = x1 * cos - x2 * sin
        rx2 = x2 * cos + x1 * sin
        result = x.clone()
        result[..., : self.dim // 2] = rx1
        result[..., self.dim // 2 : self.dim] = rx2
        return result


class Llama3RoPE(nn.Module):
    def __init__(
        self,
        dims: int,
        max_position_embeddings: int = 2048,
        traditional: bool = False,
        base: float = 10000,
        scaling_config: dict = None,
    ):
        super().__init__()
        self.dims = dims
        self.max_position_embeddings = max_position_embeddings
        self.traditional = traditional

        factor = scaling_config["factor"]
        low_freq_factor = scaling_config.get("low_freq_factor", 1.0)
        high_freq_factor = scaling_config.get("high_freq_factor", 4.0)
        old_context_len = scaling_config.get(
            "original_max_position_embeddings",
            8192,
        )

        low_freq_wavelen = old_context_len / low_freq_factor
        high_freq_wavelen = old_context_len / high_freq_factor

        freqs = base ** (torch.arange(0, dims, 2, dtype=torch.float32) / dims)
        wavelens = 2 * math.pi * freqs

        freqs = torch.where(wavelens > low_freq_wavelen, freqs * factor, freqs)
        is_medium_freq = (wavelens > high_freq_wavelen) & (wavelens < low_freq_wavelen)
        smooth_factors = (old_context_len / wavelens - low_freq_factor) / (
            high_freq_factor - low_freq_factor
        )
        smooth_freqs = freqs / ((1 - smooth_factors) / factor + smooth_factors)
        self.register_buffer(
            "_freqs", torch.where(is_medium_freq, smooth_freqs, freqs), persistent=False
        )

    def extra_repr(self):
        return (
            f"{self.dims}, traditional={self.traditional}, "
            f"max_position_embeddings={self.max_position_embeddings}"
        )

    def forward(self, x, offset: int = 0):
        freqs = self._freqs.to(x.device)
        positions = torch.arange(
            offset, offset + x.shape[1], dtype=torch.float32, device=x.device
        )
        angles = torch.outer(positions, freqs)
        cos = torch.cos(angles)
        sin = torch.sin(angles)
        x1 = x[..., : self.dims // 2]
        x2 = x[..., self.dims // 2 : self.dims]
        rx1 = x1 * cos - x2 * sin
        rx2 = x2 * cos + x1 * sin
        return torch.cat([rx1, rx2], dim=-1)


class YarnRoPE(nn.Module):
    def __init__(
        self,
        dims,
        traditional=False,
        max_position_embeddings=2048,
        base=10000,
        scaling_factor=1.0,
        original_max_position_embeddings=4096,
        beta_fast=32,
        beta_slow=1,
        mscale=1,
        mscale_all_dim=0,
    ):
        super().__init__()

        def yarn_find_correction_dim(num_rotations):
            return (
                dims
                * math.log(
                    original_max_position_embeddings / (num_rotations * 2 * math.pi)
                )
            ) / (2 * math.log(base))

        def yarn_find_correction_range():
            low = math.floor(yarn_find_correction_dim(beta_fast))
            high = math.ceil(yarn_find_correction_dim(beta_slow))
            return max(low, 0), min(high, dims - 1)

        def yarn_get_mscale(scale=1, mscale=1):
            if scale <= 1:
                return 1.0
            return 0.1 * mscale * math.log(scale) + 1.0

        def yarn_linear_ramp_mask(min_val, max_val, dim):
            if min_val == max_val:
                max_val += 0.001  # Prevent singularity

            linear_func = (torch.arange(dim, dtype=torch.float32) - min_val) / (
                max_val - min_val
            )
            return torch.clamp(linear_func, 0, 1)

        self.mscale = yarn_get_mscale(scaling_factor, mscale) / yarn_get_mscale(
            scaling_factor, mscale_all_dim
        )
        freq_extra = base ** (torch.arange(0, dims, 2, dtype=torch.float32) / dims)
        freq_inter = scaling_factor * freq_extra
        low, high = yarn_find_correction_range()
        freq_mask = 1.0 - yarn_linear_ramp_mask(low, high, dims // 2)
        self.register_buffer(
            "_freqs",
            (freq_inter * freq_extra)
            / (freq_inter * freq_mask + freq_extra * (1 - freq_mask)),
            persistent=False,
        )
        self.dims = dims
        self.traditional = traditional

    def forward(self, x, offset=0):
        if isinstance(offset, torch.Tensor):
            offset = offset.item() if offset.numel() == 1 else offset
        if self.mscale != 1.0:
            x = x.clone()
            x[..., : self.dims] = self.mscale * x[..., : self.dims]
        freqs = self._freqs.to(x.device)
        positions = torch.arange(
            offset, offset + x.shape[1], dtype=torch.float32, device=x.device
        )
        angles = torch.outer(positions, freqs)
        cos = torch.cos(angles)
        sin = torch.sin(angles)
        x1 = x[..., : self.dims // 2]
        x2 = x[..., self.dims // 2 : self.dims]
        rx1 = x1 * cos - x2 * sin
        rx2 = x2 * cos + x1 * sin
        return torch.cat([rx1, rx2], dim=-1)


class MRoPE(nn.Module):
    """Multi-dimensional RoPE for models like Qwen2-VL."""

    def __init__(
        self,
        dims: int,
        traditional: bool = False,
        base: float = 10000.0,
        mrope_section: List[int] = None,
    ):
        super().__init__()
        self.dims = dims
        self.mrope_section = mrope_section or []
        self.rope = RoPE(
            dims // len(self.mrope_section) if self.mrope_section else dims,
            traditional=traditional,
            base=base,
        )

    def forward(self, x, offset: int = 0):
        if not self.mrope_section:
            return self.rope(x, offset)

        chunks = []
        start = 0
        for i, section_size in enumerate(self.mrope_section):
            chunk = x[..., start : start + section_size]
            chunk_rope = self.rope(chunk, offset)
            chunks.append(chunk_rope)
            start += section_size

        remaining = x[..., start:]
        if remaining.shape[-1] > 0:
            chunks.append(self.rope(remaining, offset))

        return torch.cat(chunks, dim=-1)


def initialize_rope(
    dims,
    base,
    traditional,
    scaling_config: Optional[dict] = None,
    max_position_embeddings: Optional[int] = None,
):
    if scaling_config is not None:
        rope_type = scaling_config.get("type") or scaling_config.get(
            "rope_type", "default"
        )
    else:
        rope_type = "default"

    if rope_type in ["default", "linear"]:
        scale = 1 / scaling_config["factor"] if rope_type == "linear" else 1.0
        return RoPE(dims, traditional=traditional, base=base, scale=scale)

    elif rope_type == "llama3":
        return Llama3RoPE(
            dims=dims,
            max_position_embeddings=max_position_embeddings,
            traditional=traditional,
            base=base,
            scaling_config=scaling_config,
        )
    elif rope_type in ("yarn", "deepseek_yarn", "telechat3-yarn"):
        scaling_factor = scaling_config["factor"]
        rope_kwargs = {
            key: scaling_config[key]
            for key in [
                "original_max_position_embeddings",
                "beta_fast",
                "beta_slow",
                "mscale",
                "mscale_all_dim",
            ]
            if key in scaling_config
        }
        return YarnRoPE(
            dims=dims,
            max_position_embeddings=max_position_embeddings,
            traditional=traditional,
            scaling_factor=scaling_factor,
            base=base,
            **rope_kwargs,
        )
    elif rope_type == "longrope":
        return SuScaledRoPE(
            dims=dims,
            base=base,
            max_position_embeddings=max_position_embeddings,
            original_max_position_embeddings=scaling_config[
                "original_max_position_embeddings"
            ],
            short_factor=scaling_config["short_factor"],
            long_factor=scaling_config["long_factor"],
        )
    elif rope_type == "mrope":
        mrope_section = scaling_config.get("mrope_section", [])
        assert len(mrope_section) == 3, (
            f"MRoPE currently only supports 3 sections, got {len(mrope_section)}."
        )
        return MRoPE(
            dims, traditional=traditional, base=base, mrope_section=mrope_section
        )
    else:
        raise ValueError(f"Unsupported RoPE type {rope_type}")
