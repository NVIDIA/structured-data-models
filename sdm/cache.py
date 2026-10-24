# SPDX-FileCopyrightText: Copyright (c) 2026, NVIDIA CORPORATION & AFFILIATES. All rights reserved.
# SPDX-License-Identifier: Apache-2.0

from collections.abc import (
    Callable,
    Hashable,
    Iterable,
    Iterator,
    Mapping,
    MutableMapping,
)
from dataclasses import dataclass, replace
from enum import StrEnum
from typing import Self, cast

import torch
from torch import Tensor

from sdm._memory import set_pinned_max_round_threshold
from sdm.tensor.mixin import DeviceMixin


@dataclass
class KVCacheEntry(DeviceMixin):
    r"""Cached key/value projections for a single transformer block.

    Args:
        key: Cached key projection tensor.
        value: Cached value projection tensor.
    """

    key: Tensor
    value: Tensor

    def select_heads(self, num_heads: int) -> Self:
        """Retain the leading key/value heads for grouped-query attention.

        Args:
            num_heads: Number of leading K/V heads to retain.

        Returns:
            An entry with contiguous K/V copies when reducing the head count.
        """
        if num_heads >= self.key.size(-2):
            return self
        key, value = _copy_key_value(
            key=self.key[..., :num_heads, :],
            value=self.value[..., :num_heads, :],
        )
        return replace(self, key=key, value=value)

    def _tensors(self) -> Iterator[Tensor]:
        yield self.key
        yield self.value

    def _apply_tensor(self, fn: Callable[[Tensor], Tensor]) -> Self:
        return replace(self, key=fn(self.key), value=fn(self.value))


@dataclass
class QuantizedKVCacheEntry(KVCacheEntry):
    """Quantized attention projections with per-head scaling metadata.

    Keys and values have shape ``[..., rows, heads, channels]``. Scales have
    shape ``[..., 1, heads, 1]``. The query scale is learned from context
    queries and reused for prediction. The key/value tensor dtypes identify
    their storage formats; ``dtype`` is the attention output dtype.

    Args:
        key: Quantized key projections.
        value: Quantized value projections.
        key_scale: Per-head key dequantization scales.
        value_scale: Per-head value dequantization scales.
        query_scale: Per-query-head scales derived from the context.
        dtype: Attention output dtype.
    """

    key_scale: Tensor
    value_scale: Tensor
    query_scale: Tensor
    dtype: torch.dtype

    def select_heads(self, num_heads: int) -> Self:
        """Retain leading K/V heads and scales, keeping all query scales.

        Args:
            num_heads: Number of leading K/V heads to retain.

        Returns:
            A quantized entry with selected K/V heads and matching scales.
        """
        return replace(
            super().select_heads(num_heads),
            key_scale=self.key_scale[..., :num_heads, :].contiguous(),
            value_scale=self.value_scale[..., :num_heads, :].contiguous(),
        )

    def _tensors(self) -> Iterator[Tensor]:
        yield from super()._tensors()
        yield self.key_scale
        yield self.value_scale
        yield self.query_scale

    def _apply_tensor(self, fn: Callable[[Tensor], Tensor]) -> Self:
        return replace(
            super()._apply_tensor(fn),
            key_scale=fn(self.key_scale),
            value_scale=fn(self.value_scale),
            query_scale=fn(self.query_scale),
        )


class Cache(MutableMapping[Hashable, object], DeviceMixin):
    r"""A mutable mapping of model cache values."""

    class Mode(StrEnum):
        r"""The operating mode of a :class:`Cache`.

        A cache alternates between two phases: (1) recording key/value
        projections from a fit pass, and (2) replaying them across subsequent
        predict passes.
        Possible values are:

        Attributes:
            record: Allows recording of data.
            replay: Allows replaying of data.
        """

        record = "record"
        replay = "replay"

    def __init__(
        self,
        *args: Mapping[Hashable, object] | Iterable[tuple[Hashable, object]],
        **kwargs: object,
    ) -> None:
        self._mode = Cache.Mode.record
        self._items: dict[Hashable, object] = dict(*args, **kwargs)

    @property
    def is_recording(self) -> bool:
        r"""Whether the cache is in recording mode."""
        return self._mode == Cache.Mode.record

    @property
    def is_replaying(self) -> bool:
        r"""Whether the cache is in replaying mode."""
        return self._mode == Cache.Mode.replay

    def size(self) -> int:
        r"""The size in bytes of tensor data stored in this cache."""
        return sum(
            tensor.numel() * tensor.element_size()
            for tensor in self._tensors()
        )

    def freeze(self) -> Self:
        r"""Freeze the cache to replay mode."""

        def _freeze(value: object) -> None:
            if isinstance(value, Cache):
                value._mode = Cache.Mode.replay
                for item in value.values():
                    _freeze(item)
            elif isinstance(value, (list, tuple)):
                for item in value:
                    _freeze(item)
            elif isinstance(value, Mapping):
                for item in value.values():
                    _freeze(item)

        _freeze(self)
        return self

    def __setitem__(self, key: Hashable, value: object) -> None:
        if not self.is_recording:
            raise RuntimeError(
                "'__setitem__' requires the cache to be in 'record' mode"
            )
        self._items[key] = value

    def __delitem__(self, key: Hashable) -> None:
        if not self.is_recording:
            raise RuntimeError(
                "'__delitem__' requires the cache to be in 'record' mode"
            )
        del self._items[key]

    def __getitem__(self, key: Hashable) -> object:
        return self._items[key]

    def __iter__(self) -> Iterator[Hashable]:
        return iter(self._items)

    def __len__(self) -> int:
        return len(self._items)

    def __repr__(self) -> str:
        return repr(self._items)

    def __getstate__(self) -> dict[str, object]:
        state = self.__dict__.copy()
        # Stable serialization metadata: positions in the tensor traversal.
        state["_pinned_tensor_indices"] = tuple(
            index
            for index, tensor in enumerate(self._tensors())
            if tensor.is_pinned()
        )
        return state

    def __setstate__(self, state: dict[str, object]) -> None:
        pinned = set(
            cast(tuple[int, ...], state.pop("_pinned_tensor_indices", ()))
        )
        self.__dict__.update(state)
        if not pinned or not torch.cuda.is_available():
            return

        replacements: dict[int, Tensor] = {}
        for index, tensor in enumerate(self._tensors()):
            if (
                index in pinned
                and tensor.is_cpu
                and not tensor.is_pinned()
                and id(tensor) not in replacements
            ):
                if not replacements:
                    set_pinned_max_round_threshold(mb=1)
                replacements[id(tensor)] = tensor.pin_memory()

        if replacements:
            self._items = self._apply_tensor(
                lambda tensor: replacements.get(id(tensor), tensor)
            )._items

    def _tensors(self) -> Iterator[Tensor]:
        def _iter_tensors(value: object) -> Iterator[Tensor]:
            if isinstance(value, Tensor):
                yield value
            elif isinstance(value, DeviceMixin):
                yield from value._tensors()
            elif isinstance(value, list | tuple):
                for item in value:
                    yield from _iter_tensors(item)
            elif isinstance(value, Mapping):
                for item in value.values():
                    yield from _iter_tensors(item)

        for value in self.values():
            yield from _iter_tensors(value)

    def _apply_tensor(self, fn: Callable[[Tensor], Tensor]) -> Self:
        def _apply(value: object) -> object:
            if isinstance(value, Tensor):
                return fn(value)
            if isinstance(value, DeviceMixin):
                return value._apply_tensor(fn)
            if isinstance(value, list):
                return [_apply(item) for item in value]
            if isinstance(value, tuple):
                return tuple(_apply(item) for item in value)
            if isinstance(value, Mapping):
                return {key: _apply(item) for key, item in value.items()}
            return value

        out = self.__class__(
            {key: _apply(value) for key, value in self.items()}
        )
        out._mode = self._mode
        return out


def _copy_key_value(key: Tensor, value: Tensor) -> tuple[Tensor, Tensor]:
    return (
        key.clone(memory_format=torch.contiguous_format),
        value.clone(memory_format=torch.contiguous_format),
    )


# Keep the guard for PyTorch 2.7; 2.8+ can use the decorator directly.
if hasattr(torch.compiler, "nested_compile_region"):
    # Compile cache copies separately to free each layer's full K/V tensors.
    _copy_key_value = torch.compiler.nested_compile_region(_copy_key_value)
