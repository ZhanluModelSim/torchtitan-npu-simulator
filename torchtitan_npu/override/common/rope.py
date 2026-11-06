# Copyright (c) Meta Platforms, Inc. and affiliates.
# All rights reserved.
#
# This source code is licensed under the BSD-style license found in the
# LICENSE file in the root directory of this source tree.

"""Override: provide torch-compatible and AscendC fused rotary embeddings.

The workaround variant uses pre-expanded cosine/sine caches; the AscendC fused
variants call ``torch_npu.npu_rotary_mul``. The fused partial-RoPE wrapper is
imported lazily on first call, so this module stays importable without an NPU
stack. Select one variant per RoPE config.
"""

import weakref
from dataclasses import dataclass

import torch
import torch_npu
from torchtitan.config import derive, override
from torchtitan.models.common.rope import (
    ComplexRoPE,
    CosSinRoPE,
    _reshape_for_broadcast,
)

from torchtitan_npu.models.common.rope import HalfRotation
from torchtitan_npu.patches.torchtitan.models.common.rope import (
    SplitComplexRoPEConfig,
    SplitCosSinRoPEConfig,
)

_ROPE_CACHE_FIELDS = (
    "dim",
    "max_context_length",
    "theta",
    "scaling",
    "scaling_factor",
    "low_freq_factor",
    "high_freq_factor",
    "original_max_position_embeddings",
    "rope_factor",
    "beta_fast",
    "beta_slow",
    "original_seq_len",
    "truncate",
)
_INTERLEAVED_CACHE_POOL: weakref.WeakValueDictionary[tuple[object, ...], torch.Tensor] = weakref.WeakValueDictionary()


def _interleaved_cache_key(rope) -> tuple[object, ...]:
    config = rope.config
    return (
        *(getattr(config, name, None) for name in _ROPE_CACHE_FIELDS),
        rope.cache.device,
        rope.cache.dtype,
    )


class _InterleavedCacheMixin:
    def __init__(self, config: ComplexRoPE.Config):
        super().__init__(config)  # pyrefly: ignore [bad-argument-count]
        if self.cache.device.type == "meta":
            # ``to_empty`` materializes every buffer in the meta-built model.
            # Keep only a device-bearing placeholder here so long-context
            # caches are created once per pool key during ``init_states``.
            self.cache = self.cache.new_empty(1)
        else:
            self._expand_interleaved_cache()

    def _init_self_buffers(
        self,
        *,
        buffer_device: torch.device | None = None,
    ) -> None:
        super()._init_self_buffers(  # pyrefly: ignore [missing-attribute]
            buffer_device=buffer_device
        )
        self._expand_interleaved_cache()

    def _expand_interleaved_cache(self) -> None:
        complex_cache = self.cache
        key = _interleaved_cache_key(self)
        cache = _INTERLEAVED_CACHE_POOL.get(key)
        if cache is None:
            cache = torch.stack(
                (
                    complex_cache.real.repeat_interleave(2, dim=-1),
                    complex_cache.imag.repeat_interleave(2, dim=-1),
                )
            )
            _INTERLEAVED_CACHE_POOL[key] = cache
        self.cache = cache

    def _reshape_cache(
        self,
        query: torch.Tensor,
        positions: torch.Tensor | None = None,
    ) -> tuple[torch.Tensor, torch.Tensor]:
        cos_cache, sin_cache = self.cache.unbind(0)
        return (
            _reshape_for_broadcast(cos_cache, query.shape, positions),
            _reshape_for_broadcast(sin_cache, query.shape, positions),
        )


def _apply_interleaved_rope(
    x: torch.Tensor,
    cos: torch.Tensor,
    sin: torch.Tensor,
) -> torch.Tensor:
    x_float = x.float()
    rotated = torch.stack(
        (-x_float[..., 1::2], x_float[..., ::2]),
        dim=-1,
    ).flatten(-2)
    return (x_float * cos + rotated * sin).type_as(x)


class WorkaroundComplexRoPE(  # pyrefly: ignore [inconsistent-inheritance]
    _InterleavedCacheMixin, ComplexRoPE
):
    @dataclass(kw_only=True, slots=True)
    class Config(SplitComplexRoPEConfig):
        pass

    @staticmethod
    def apply_rotary_emb(  # pyrefly: ignore [bad-override]
        query: torch.Tensor,
        key: torch.Tensor | None,
        rope_cache: tuple[torch.Tensor, torch.Tensor],
        *,
        inverse: bool = False,
    ) -> torch.Tensor | tuple[torch.Tensor, torch.Tensor]:
        cos, sin = rope_cache
        if inverse:
            sin = -sin
        query_out = _apply_interleaved_rope(query, cos, sin)
        if key is None:
            return query_out
        return query_out, _apply_interleaved_rope(key, cos, sin)


@override(
    target=ComplexRoPE.Config,
    exact=True,
    description="Torch-compatible interleaved ComplexRoPE (workaround)",
)
def workaround(cfg: ComplexRoPE.Config) -> WorkaroundComplexRoPE.Config:
    return derive(cfg, WorkaroundComplexRoPE.Config)


class AscComplexRoPE(WorkaroundComplexRoPE):
    @dataclass(kw_only=True, slots=True)
    class Config(WorkaroundComplexRoPE.Config):
        pass

    @staticmethod
    def apply_rotary_emb(  # pyrefly: ignore [bad-override]
        query: torch.Tensor,
        key: torch.Tensor | None,
        rope_cache: tuple[torch.Tensor, torch.Tensor],
        *,
        inverse: bool = False,
    ) -> torch.Tensor | tuple[torch.Tensor, torch.Tensor]:
        cos, sin = rope_cache
        cos = cos.to(query.dtype)
        sin = sin.to(query.dtype)
        if inverse:
            sin = -sin
        xq_out = torch_npu.npu_rotary_mul(query.float(), cos, sin, rotary_mode="interleave").type_as(query)
        if key is None:
            return xq_out
        xk_out = torch_npu.npu_rotary_mul(
            key.float(), cos.to(key.dtype), sin.to(key.dtype), rotary_mode="interleave"
        ).type_as(key)
        return xq_out, xk_out


class AscCosSinRoPE(CosSinRoPE):
    @dataclass(kw_only=True, slots=True)
    class Config(SplitCosSinRoPEConfig):
        pass

    @staticmethod
    def apply_rotary_emb(
        query: torch.Tensor,
        key: torch.Tensor | None,
        rope_cache: torch.Tensor,
        *,
        inverse: bool = False,
    ) -> torch.Tensor | tuple[torch.Tensor, torch.Tensor]:
        if inverse:
            raise NotImplementedError("CosSinRoPE does not support inverse rotation.")
        head_dim = query.shape[-1]
        cos = rope_cache[..., :head_dim].to(query.dtype)
        sin = rope_cache[..., head_dim:].to(query.dtype)
        xq_out = torch_npu.npu_rotary_mul(query.float(), cos, sin, rotary_mode="half").type_as(query)
        if key is None:
            return xq_out
        xk_out = torch_npu.npu_rotary_mul(
            key.float(), cos.to(key.dtype), sin.to(key.dtype), rotary_mode="half"
        ).type_as(key)
        return xq_out, xk_out


@override(
    target=ComplexRoPE.Config,
    exact=True,
    description="AscendC fused ComplexRoPE via torch_npu.npu_rotary_mul (interleave mode)",
)
def asc_complex(cfg: ComplexRoPE.Config) -> AscComplexRoPE.Config:
    return derive(cfg, AscComplexRoPE.Config)


@override(
    target=CosSinRoPE.Config,
    description="AscendC fused CosSinRoPE via torch_npu.npu_rotary_mul (half mode)",
)
def asc_cossin(cfg: CosSinRoPE.Config) -> AscCosSinRoPE.Config:
    return derive(cfg, AscCosSinRoPE.Config)


class AscPartialComplexRoPE(WorkaroundComplexRoPE):
    """Partial RoPE fused into one ``inplace_partial_rotary_mul`` per site.

    ``forward`` takes the full-width tensor; the wrapper clones it and the
    kernel rotates only the ``partial_slice`` span, so no slice/cat is
    materialized. Eager and ``torch.compile`` share the same path.
    """

    @dataclass(kw_only=True, slots=True)
    class Config(SplitComplexRoPEConfig):  # pyrefly: ignore [bad-override]
        def __post_init__(self) -> None:
            if self.split < 0:
                raise ValueError(f"split must be non-negative, got {self.split}.")
            if self.dim <= 0 or self.dim % 2:
                raise ValueError(f"rotary dim must be a positive even width, got {self.dim}.")

    def forward(  # pyrefly: ignore [bad-override]
        self,
        query: torch.Tensor,
        key: torch.Tensor | None = None,
        positions: torch.Tensor | None = None,
        *,
        inverse: bool = False,
    ) -> torch.Tensor | tuple[torch.Tensor, torch.Tensor]:
        # Lazy CANN import: keeps this module importable without an NPU stack.
        from torchtitan_npu.ops.ascendc.inplace_partial_rotary_mul import (
            inplace_partial_rotary_mul,
        )

        split = self.config.split  # pyrefly: ignore [missing-attribute]
        expected = split + self.config.dim
        if query.shape[-1] != expected:
            raise ValueError(
                f"{type(self).__name__} tail-RoPE contract violated: query width "
                f"{query.shape[-1]} != split {split} + rotary dim {self.config.dim}."
            )
        if key is not None and key.shape[-1] != expected:
            raise ValueError(
                f"{type(self).__name__} tail-RoPE contract violated: key width "
                f"{key.shape[-1]} != split {split} + rotary dim {self.config.dim}."
            )
        cos, sin = self._reshape_cache(query[..., split:], positions)
        if inverse:
            sin = -sin
        out_q = inplace_partial_rotary_mul(
            query,
            cos,
            sin,
            rotary_mode="interleave",
            partial_slice=[split, split + self.config.dim],
        )
        if key is None:
            return out_q
        out_k = inplace_partial_rotary_mul(
            key,
            cos,
            sin,
            rotary_mode="interleave",
            partial_slice=[split, split + self.config.dim],
        )
        return out_q, out_k


@override(
    target=SplitComplexRoPEConfig,
    exact=True,
    description=("AscendC fused partial RoPE: one CANN inplace_partial_rotary_mul per site"),
)
def asc_partial(cfg: SplitComplexRoPEConfig) -> AscPartialComplexRoPE.Config:
    return derive(cfg, AscPartialComplexRoPE.Config)


def _npu_rotary_mul_shared_axis(
    x: torch.Tensor,
    cos: torch.Tensor,
    sin: torch.Tensor,
    rotary_mode: str,
) -> torch.Tensor:
    """``npu_rotary_mul`` requires a shared batch axis for position tables.

    Fold batch into sequence when the tables carry per-sample positions,
    so distinct positions for every sample are retained.
    """
    values = x.float()
    if x.ndim == 3:
        values = values.unsqueeze(0)
    if cos.ndim == 3:
        cos, sin = cos.unsqueeze(0), sin.unsqueeze(0)
    shape = values.shape
    if cos.shape[0] != 1:
        values = values.flatten(0, 1).unsqueeze(0)
        cos = cos.expand(shape[0], shape[1], -1, -1).flatten(0, 1).unsqueeze(0)
        sin = sin.expand(shape[0], shape[1], -1, -1).flatten(0, 1).unsqueeze(0)
    output = torch_npu.npu_rotary_mul(
        values.contiguous(),
        cos.contiguous(),
        sin.contiguous(),
        rotary_mode=rotary_mode,
    )
    output = output.reshape(shape)
    if x.ndim == 3:
        output = output.squeeze(0)
    return output


class AscHalfRotation(HalfRotation):
    @dataclass(kw_only=True, slots=True)
    class Config(HalfRotation.Config):
        pass

    def forward(self, x, cos, sin, *, inverse=False):
        if inverse:
            sin = -sin
        # The seam contract is half-width tables (one entry per frequency);
        # npu_rotary_mul consumes full-width tables.
        cos, sin = torch.cat((cos, cos), dim=-1), torch.cat((sin, sin), dim=-1)
        return _npu_rotary_mul_shared_axis(x, cos, sin, "half").to(x.dtype)


@override(
    target=HalfRotation.Config,
    exact=True,
    description="AscendC fused half rotation for external tables via torch_npu.npu_rotary_mul",
)
def asc_half_rotation(cfg: HalfRotation.Config) -> AscHalfRotation.Config:
    return derive(cfg, AscHalfRotation.Config)
