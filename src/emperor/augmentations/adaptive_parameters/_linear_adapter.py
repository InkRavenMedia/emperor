from __future__ import annotations

import torch
from torch import Tensor

from emperor.augmentations.adaptive_parameters._config import (
    AdaptiveLinearLayerConfig,
    AdaptiveParameterAugmentationConfig,
)
from emperor.augmentations.adaptive_parameters._validation import (
    AdaptiveLinearValidator,
)
from emperor.linears import LinearAbstract


class AdaptiveLinearLayer(LinearAbstract):
    VALIDATOR = AdaptiveLinearValidator

    def __init__(
        self,
        cfg: AdaptiveLinearLayerConfig,
        overrides: AdaptiveLinearLayerConfig | None = None,
    ):
        super().__init__(cfg, overrides)
        self.adaptive_cfg = self.cfg.adaptive_augmentation_config
        self.diagonal_config = self.adaptive_cfg.diagonal_config
        self.weight_config = self.adaptive_cfg.weight_config
        self.bias_config = self.adaptive_cfg.bias_config
        self.mask_config = self.adaptive_cfg.mask_config
        self.has_adaptive_augmentation: bool = self.__has_adaptive_augmentation()
        self.adaptive_behaviour = self.__init_behaviour()

    def __has_adaptive_augmentation(self) -> bool:
        return any(
            config is not None
            for config in (
                self.diagonal_config,
                self.weight_config,
                self.bias_config,
                self.mask_config,
            )
        )

    def __init_behaviour(self):
        if not self.has_adaptive_augmentation:
            return None

        overrides = AdaptiveParameterAugmentationConfig(
            input_dim=self.input_dim,
            output_dim=self.output_dim,
        )
        return self.adaptive_cfg.build(overrides)

    def forward(
        self,
        X: Tensor,
    ) -> Tensor:
        self.VALIDATOR.validate_input_is_2d(X)
        if not self.has_adaptive_augmentation:
            return self._compute_affine_transformation_callback(
                self.weight_params, self.bias_params, X
            )
        return self.adaptive_behaviour(
            self._compute_affine_transformation_callback,
            self.weight_params,
            self.bias_params,
            X,
        )

    def get_auxiliary_loss(self) -> Tensor | None:
        if self.adaptive_behaviour is None:
            return None
        return self.adaptive_behaviour.get_auxiliary_loss()

    def _compute_affine_transformation_callback(
        self, weights: Tensor, bias: Tensor | None, X: Tensor
    ) -> Tensor:
        output = self.__compute_linear_transformation(X, weights)
        return self.__add_bias_parameters(output, bias)

    def __compute_linear_transformation(self, X: Tensor, weights: Tensor) -> Tensor:
        if weights.dim() == 3:
            self.VALIDATOR.validate_weight_context_count(X, weights)
            if X.dim() == 3:
                return torch.bmm(X, weights)
            return torch.einsum("ij,ijk->ik", X, weights)
        return torch.matmul(X, weights)

    def __add_bias_parameters(
        self, X: Tensor, bias_params: Tensor | None = None
    ) -> Tensor:
        if bias_params is not None:
            prepared_bias = self.__prepare_bias_parameters(X, bias_params)
            return X + prepared_bias
        return X

    def __prepare_bias_parameters(
        self,
        X: Tensor,
        bias_params: Tensor,
    ) -> Tensor:
        if bias_params.dim() != 2:
            return bias_params
        self.VALIDATOR.validate_bias_context_count(X, bias_params)
        if X.dim() == 3:
            return bias_params.unsqueeze(1)
        return bias_params
