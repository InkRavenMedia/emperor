"""Private self-attention projection implementation."""

from dataclasses import replace
from typing import TYPE_CHECKING

import torch.nn as nn
from torch import Tensor

from emperor.attention._ops.projection import ProjectorBase
from emperor.attention._variants.self_attention.config import (
    SelfAttentionProjectionStrategy,
)

if TYPE_CHECKING:
    from emperor.attention._config import MultiHeadAttentionConfig
    from emperor.attention._runtime import MultiHeadAttentionInputs


class SelfAttentionProjector(ProjectorBase):
    def __init__(self, cfg: "MultiHeadAttentionConfig"):
        super().__init__(cfg)
        self.projection_strategy: SelfAttentionProjectionStrategy = (
            self.cfg.projection_strategy
        )
        self.qkv_model: nn.Module | None = None
        self.query_model: nn.Module | None = None
        self.key_value_model: nn.Module | None = None
        self.key_model: nn.Module | None = None
        self.value_model: nn.Module | None = None
        self.__build_projection_models()

    def _build_output_model(self) -> nn.Module:
        return self._create_model(self.embedding_dim, self.embedding_dim)

    def __build_projection_models(self) -> None:
        match self.projection_strategy:
            case SelfAttentionProjectionStrategy.FUSED:
                self.__build_fused_qkv_projection_model()
            case SelfAttentionProjectionStrategy.FUSED_KEY_VALUE:
                self.__build_query_and_fused_key_value_projection_models()
            case SelfAttentionProjectionStrategy.SEPARATE:
                self.__build_separate_qkv_projection_models()
            case _:
                raise ValueError(
                    "projection_strategy must be FUSED, FUSED_KEY_VALUE, or "
                    "SEPARATE for "
                    f"SelfAttentionProjector, got {self.projection_strategy!r}."
                )

    def __build_fused_qkv_projection_model(self) -> None:
        self.qkv_model = self._create_model(self.embedding_dim, self.embedding_dim * 3)

    def __build_query_and_fused_key_value_projection_models(self) -> None:
        self.query_model = self._create_model(self.embedding_dim, self.embedding_dim)
        self.key_value_model = self._create_model(
            self.embedding_dim, self.embedding_dim * 2
        )

    def __build_separate_qkv_projection_models(self) -> None:
        self.query_model = self._create_model(self.embedding_dim, self.embedding_dim)
        self.key_model = self._create_model(self.embedding_dim, self.embedding_dim)
        self.value_model = self._create_model(self.embedding_dim, self.embedding_dim)

    def _compute_qkv_projections(
        self,
        attention_inputs: "MultiHeadAttentionInputs",
    ) -> "MultiHeadAttentionInputs":
        match self.projection_strategy:
            case SelfAttentionProjectionStrategy.FUSED:
                query, key, value = self.__compute_fused_qkv_projections(
                    attention_inputs.query,
                )
            case SelfAttentionProjectionStrategy.FUSED_KEY_VALUE:
                query, key, value = self.__compute_fused_key_value_projections(
                    attention_inputs.query,
                    attention_inputs.key,
                )
            case SelfAttentionProjectionStrategy.SEPARATE:
                query, key, value = self.__compute_separate_qkv_projections(
                    attention_inputs.query,
                    attention_inputs.key,
                    attention_inputs.value,
                )
            case _:
                raise AssertionError(
                    "projection_strategy was validated during construction."
                )
        return replace(attention_inputs, query=query, key=key, value=value)

    def __compute_fused_qkv_projections(
        self,
        query: Tensor,
    ) -> tuple[Tensor, Tensor, Tensor]:
        qkv_projection = self._compute_projection(
            query,
            self.qkv_model,
        )
        return self.__split_self_attention_projection(qkv_projection)

    def __compute_fused_key_value_projections(
        self,
        query: Tensor,
        key: Tensor,
    ) -> tuple[Tensor, Tensor, Tensor]:
        q_projection = self._compute_projection(
            query,
            self.query_model,
        )
        key_value_projection = self._compute_projection(
            key,
            self.key_value_model,
        )
        k_projection, v_projection = self.__split_key_value_projection(
            key_value_projection
        )
        return q_projection, k_projection, v_projection

    def __compute_separate_qkv_projections(
        self,
        query: Tensor,
        key: Tensor,
        value: Tensor,
    ) -> tuple[Tensor, Tensor, Tensor]:
        q_projection = self._compute_projection(
            query,
            self.query_model,
        )
        k_projection = self._compute_projection(
            key,
            self.key_model,
        )
        v_projection = self._compute_projection(
            value,
            self.value_model,
        )
        return q_projection, k_projection, v_projection

    def __split_self_attention_projection(
        self, qkv_projections: Tensor
    ) -> tuple[Tensor, Tensor, Tensor]:
        query, key, value = qkv_projections.chunk(3, dim=-1)
        return query, key, value

    def __split_key_value_projection(
        self, key_value_projection: Tensor
    ) -> tuple[Tensor, Tensor]:
        key, value = key_value_projection.chunk(2, dim=-1)
        return key, value
