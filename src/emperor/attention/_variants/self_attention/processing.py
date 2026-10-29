"""Private self-attention processing implementation."""

from dataclasses import replace
from typing import TYPE_CHECKING

import torch
import torch.nn.functional as F
from torch import Tensor

from emperor.attention._ops.processing import ProcessorBase

if TYPE_CHECKING:
    from emperor.attention._runtime import (
        AttentionRuntimeLayout,
        MultiHeadAttentionInputs,
    )


class SelfAttentionProcessor(ProcessorBase):
    def compute_attention(
        self,
        attention_inputs: "MultiHeadAttentionInputs",
    ) -> tuple[Tensor, Tensor | None]:
        runtime_layout = attention_inputs.runtime_layout
        attention_weights = self._compute_masked_attention_weights(attention_inputs)
        weighted_values = self.__compute_weighted_values(
            attention_inputs,
            attention_weights,
        )
        attention_output = self._compute_attention_output(
            weighted_values, runtime_layout
        )
        attention_weights = self.__format_attention_weights(
            attention_weights, runtime_layout
        )

        return attention_output, attention_weights

    def _compute_masked_attention_weights(
        self,
        attention_inputs: "MultiHeadAttentionInputs",
    ) -> Tensor:
        raw_attention_logits = self._compute_raw_masked_attention_logits(
            attention_inputs
        )
        normalized_attention_weights = self._compute_normalized_attention_weights(
            raw_attention_logits
        )
        return F.dropout(
            normalized_attention_weights,
            p=self.dropout_probability,
            training=self.training,
        )

    def _compute_raw_masked_attention_logits(
        self,
        attention_inputs: "MultiHeadAttentionInputs",
    ) -> Tensor:
        if self.cfg.rotary_base is not None:
            attention_inputs = replace(
                attention_inputs,
                query=self.__rotate_positions(attention_inputs.query),
                key=self.__rotate_positions(attention_inputs.key),
            )
        scaled_inputs = replace(
            attention_inputs,
            query=self.__scale_query(attention_inputs.query),
        )
        transposed_key = scaled_inputs.key.transpose(-2, -1)
        attention_logits = torch.bmm(scaled_inputs.query, transposed_key)
        attention_logits = self.__add_relative_position_logits_if_available(
            scaled_inputs,
            attention_logits,
        )
        masked_attention_logits = self.__add_attention_mask_if_available(
            attention_logits,
            scaled_inputs.merged_attention_mask,
        )
        return masked_attention_logits

    def __rotate_positions(self, features: Tensor) -> Tensor:
        head_dim = features.shape[-1]
        frequency_dtype = (
            torch.float64 if features.dtype == torch.float64 else torch.float32
        )
        pair_indices = torch.arange(
            0, head_dim, 2, device=features.device, dtype=frequency_dtype
        )
        inverse_frequencies = self.cfg.rotary_base ** (-pair_indices / head_dim)
        positions = torch.arange(
            features.shape[-2], device=features.device, dtype=frequency_dtype
        )
        angles = positions[:, None] * inverse_frequencies
        cosine, sine = angles.cos().to(features.dtype), angles.sin().to(features.dtype)
        even, odd = features[..., 0::2], features[..., 1::2]
        return torch.stack(
            (even * cosine - odd * sine, even * sine + odd * cosine), dim=-1
        ).flatten(-2)

    def _compute_normalized_attention_weights(
        self,
        raw_attention_logits: Tensor,
    ) -> Tensor:
        fully_masked_rows = torch.isneginf(raw_attention_logits).all(
            dim=-1, keepdim=True
        )
        safe_attention_logits = raw_attention_logits.masked_fill(fully_masked_rows, 0.0)
        normalized_attention_weights = F.softmax(safe_attention_logits, dim=-1)
        normalized_attention_weights_with_zeroed_masked_rows = (
            normalized_attention_weights.masked_fill(fully_masked_rows, 0.0)
        )
        return normalized_attention_weights_with_zeroed_masked_rows

    def __scale_query(self, query: Tensor) -> Tensor:
        head_dim = query.size(-1)
        return query * head_dim**-0.5

    def __add_relative_position_logits_if_available(
        self,
        attention_inputs: "MultiHeadAttentionInputs",
        attention_weights: Tensor,
    ) -> Tensor:
        relative_position_logits = self.__compute_relative_position_logits_for_inputs(
            attention_inputs
        )
        if relative_position_logits is not None:
            return relative_position_logits + attention_weights
        return attention_weights

    def __compute_relative_position_logits_for_inputs(
        self,
        attention_inputs: "MultiHeadAttentionInputs",
    ) -> Tensor | None:
        source_sequence_dimension = attention_inputs.key.dim() - 2
        source_sequence_length = attention_inputs.key.size(source_sequence_dimension)
        return self._compute_relative_position_logits(
            attention_inputs.query,
            source_sequence_length,
            attention_inputs.runtime_layout,
            query_is_scaled=True,
        )

    def __add_attention_mask_if_available(
        self,
        attention_weights: Tensor,
        merged_attention_mask: Tensor | None = None,
    ) -> Tensor:
        if merged_attention_mask is not None:
            return attention_weights + merged_attention_mask
        return attention_weights

    def __compute_weighted_values(
        self,
        attention_inputs: "MultiHeadAttentionInputs",
        attention_weights: Tensor,
    ) -> Tensor:
        weighted_values = torch.bmm(attention_weights, attention_inputs.value)
        weighted_values = weighted_values.transpose(0, 1)
        weighted_values = weighted_values.contiguous()
        target_sequence_length = weighted_values.size(0)
        batch_size = self.__resolve_batch_size(attention_inputs.runtime_layout)
        return weighted_values.view(
            target_sequence_length * batch_size,
            self.value_projection_dim,
        )

    def __resolve_batch_size(
        self,
        runtime_layout: "AttentionRuntimeLayout | None",
    ) -> int:
        if runtime_layout is not None:
            return runtime_layout.batch_size
        return self.batch_size

    def __format_attention_weights(
        self,
        attention_weights: Tensor,
        runtime_layout: "AttentionRuntimeLayout | None",
    ) -> Tensor | None:
        if not self.return_attention_weights_flag:
            return None

        batch_size = self.__resolve_batch_size(runtime_layout)
        target_sequence_length = self.__resolve_target_sequence_length(runtime_layout)
        source_sequence_length = attention_weights.size(-1)
        attention_weights_shape = (
            batch_size,
            self.num_heads,
            target_sequence_length,
            source_sequence_length,
        )
        attention_weights = attention_weights.view(attention_weights_shape)
        attention_weights = self.__maybe_average_attention_weights(attention_weights)

        if runtime_layout is not None and not runtime_layout.input_was_batched:
            return attention_weights.squeeze(0)
        return attention_weights

    def __resolve_target_sequence_length(
        self,
        runtime_layout: "AttentionRuntimeLayout | None",
    ) -> int:
        if runtime_layout is not None:
            return runtime_layout.target_sequence_length
        return self.target_sequence_length

    def __maybe_average_attention_weights(self, attention_weights: Tensor) -> Tensor:
        if self.average_attention_weights_flag:
            return attention_weights.mean(dim=1)
        return attention_weights
