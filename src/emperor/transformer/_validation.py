from typing import TYPE_CHECKING

import torch

from emperor._validation import (
    ValidatorBase,
    _adaptive_grouping_configs,
    _configuration_visits,
    _first_adaptive_grouping_path,
    _validate_adaptive_sequence_input,
    _validate_grouped_row_preservation,
)
from emperor.config import ConfigBase

if TYPE_CHECKING:
    from torch import Tensor

    from emperor.transformer._feed_forward import FeedForward
    from emperor.transformer._layers import (
        TransformerDecoderLayer,
        TransformerEncoderLayer,
    )
    from emperor.transformer._model import Transformer


class TransformerValidator(ValidatorBase):
    OPTIONAL_FIELDS = {
        "override_config",
        "cross_attention_config",
        "residual_config",
        "normalization",
    }

    # --- build-time structural validation ---

    @classmethod
    def validate_transformer(cls, model: "Transformer") -> None:
        from emperor.layers import NormalizationOptions

        final_normalization = getattr(model.cfg, "final_normalization", None)
        if final_normalization is not None and not isinstance(
            final_normalization, NormalizationOptions
        ):
            raise TypeError(
                "final_normalization must be a NormalizationOptions value or None"
            )
        encoder_stack_config = model.cfg.encoder_stack_config
        decoder_stack_config = model.cfg.decoder_stack_config
        if encoder_stack_config is None and decoder_stack_config is None:
            raise ValueError(
                "TransformerConfig requires at least one of "
                "encoder_stack_config or decoder_stack_config to be set; "
                "both are None."
            )
        cls._validate_stack_config_types(
            encoder_stack_config,
            decoder_stack_config,
        )
        cls._validate_outer_grouped_gates(
            encoder_stack_config,
            "TransformerConfig.encoder_stack_config",
        )
        cls._validate_outer_grouped_gates(
            decoder_stack_config,
            "TransformerConfig.decoder_stack_config",
        )
        cls._validate_decoder_cross_attention_has_encoder(
            encoder_stack_config, decoder_stack_config
        )

    @classmethod
    def _validate_outer_grouped_gates(cls, config, path: str) -> None:
        if config is None:
            return
        from emperor.layers import (
            LayerConfig,
            LayerStackConfig,
            RecurrentCompositionConfig,
        )
        from emperor.transformer._config import (
            TransformerDecoderLayerConfig,
            TransformerEncoderLayerConfig,
        )

        gate_configs: tuple[tuple[str, object | None], ...]
        nested_configs: tuple[tuple[str, object], ...] = ()
        if isinstance(config, RecurrentCompositionConfig):
            gate_configs = (
                (f"{path}.gate_config", getattr(config, "gate_config", None)),
            )
            nested_configs = tuple(
                (f"{path}.{field_name}", transition_config)
                for field_name, transition_config in config._transition_config_items()
            )
        elif isinstance(config, LayerStackConfig):
            layer_config = config.layer_config
            gate_configs = ((f"{path}.shared_gate_config", config.shared_gate_config),)
            if isinstance(layer_config, LayerConfig):
                gate_configs += (
                    (f"{path}.layer_config.gate_config", layer_config.gate_config),
                )
                if layer_config.layer_model_config is not None:
                    nested_configs = (
                        (
                            f"{path}.layer_config.layer_model_config",
                            layer_config.layer_model_config,
                        ),
                    )
        elif isinstance(config, LayerConfig):
            gate_configs = ((f"{path}.gate_config", config.gate_config),)
            if config.layer_model_config is not None:
                nested_configs = (
                    (f"{path}.layer_model_config", config.layer_model_config),
                )
        else:
            return

        for gate_path, gate_config in gate_configs:
            if gate_config is None:
                continue
            grouping_path = _first_adaptive_grouping_path(
                gate_config,
                root=gate_path,
            )
            if grouping_path is not None:
                raise ValueError(
                    "Enabled adaptive parameter grouping is not supported in an "
                    "outer Transformer gate because that gate receives rank-three "
                    f"token tensors. Found grouping at {grouping_path}."
                )

        for nested_path, nested_config in nested_configs:
            if isinstance(
                nested_config,
                (TransformerEncoderLayerConfig, TransformerDecoderLayerConfig),
            ):
                continue
            cls._validate_outer_grouped_gates(nested_config, nested_path)

    @staticmethod
    def _validate_stack_config_types(*stack_configs) -> None:
        from emperor.layers import LayerStackConfig, RecurrentCompositionConfig

        for stack_config in stack_configs:
            if stack_config is None:
                continue
            if not isinstance(
                stack_config,
                (LayerStackConfig, RecurrentCompositionConfig),
            ):
                raise TypeError(
                    "Transformer stack configurations must be LayerStackConfig or "
                    "RecurrentCompositionConfig, got "
                    f"{type(stack_config).__name__}."
                )

    @classmethod
    def _validate_decoder_cross_attention_has_encoder(
        cls,
        encoder_stack_config,
        decoder_stack_config,
    ) -> None:
        if encoder_stack_config is not None or decoder_stack_config is None:
            return
        decoder_layer_config = cls._find_decoder_layer_config(decoder_stack_config)
        if (
            decoder_layer_config is not None
            and decoder_layer_config.cross_attention_config is not None
        ):
            raise ValueError(
                "A decoder-only Transformer (no encoder_stack_config) must "
                "configure the decoder layer with cross_attention_config=None; "
                "cross-attention requires encoder output."
            )

    @classmethod
    def _find_decoder_layer_config(cls, config):
        from emperor.transformer._config import TransformerDecoderLayerConfig

        if isinstance(config, TransformerDecoderLayerConfig):
            return config
        for field_name in ("block_config", "layer_config", "layer_model_config"):
            nested_config = getattr(config, field_name, None)
            if nested_config is None:
                continue
            match = cls._find_decoder_layer_config(nested_config)
            if match is not None:
                return match
        return None

    @classmethod
    def validate_encoder_layer(cls, model: "TransformerEncoderLayer") -> None:
        cls.validate_required_fields(model.cfg)
        cls.validate_field_types(model.cfg)
        cls.validate_dimensions(embedding_dim=model.embedding_dim)
        cls._validate_layer_norm_position(model.layer_norm_position)
        cls._validate_encoder_attention_config(model.cfg.attention_config)
        cls._validate_soft_moe_attention(
            model.cfg.feed_forward_config, model.cfg.attention_config
        )
        cls._validate_feed_forward_grouping(
            model.cfg.feed_forward_config,
            owner_name="TransformerEncoderLayerConfig",
        )
        cls._validate_residual_history_bridge(
            model.cfg.residual_config,
            owner_name="TransformerEncoderLayerConfig",
        )

    @classmethod
    def validate_decoder_layer(cls, model: "TransformerDecoderLayer") -> None:
        cls.validate_required_fields(model.cfg)
        cls.validate_field_types(model.cfg)
        cls.validate_dimensions(embedding_dim=model.embedding_dim)
        cls._validate_layer_norm_position(model.layer_norm_position)
        cls._validate_decoder_self_attention_config(model.cfg.self_attention_config)
        cls._validate_decoder_cross_attention_config(model.cfg.cross_attention_config)
        cls._validate_soft_moe_attention(
            model.cfg.feed_forward_config,
            model.cfg.self_attention_config,
            model.cfg.cross_attention_config,
        )
        cls._validate_feed_forward_grouping(
            model.cfg.feed_forward_config,
            owner_name="TransformerDecoderLayerConfig",
        )
        cls._validate_residual_history_bridge(
            model.cfg.residual_config,
            owner_name="TransformerDecoderLayerConfig",
        )

    @staticmethod
    def _validate_encoder_attention_config(attention_config) -> None:
        from emperor.attention import (
            MixerAttentionConfig,
            MixtureOfAttentionHeadsConfig,
            SelfAttentionConfig,
        )

        if not isinstance(
            attention_config,
            (
                SelfAttentionConfig,
                MixtureOfAttentionHeadsConfig,
                MixerAttentionConfig,
            ),
        ):
            raise TypeError(
                "attention_config must be a SelfAttentionConfig, "
                "MixtureOfAttentionHeadsConfig, or MixerAttentionConfig, got "
                f"{type(attention_config).__name__}."
            )

    @staticmethod
    def _validate_decoder_self_attention_config(attention_config) -> None:
        from emperor.attention import (
            MixerAttentionConfig,
            MixtureOfAttentionHeadsConfig,
            SelfAttentionConfig,
        )

        if not isinstance(
            attention_config,
            (
                SelfAttentionConfig,
                MixtureOfAttentionHeadsConfig,
                MixerAttentionConfig,
            ),
        ):
            raise TypeError(
                "self_attention_config must be a SelfAttentionConfig, "
                "MixtureOfAttentionHeadsConfig, or MixerAttentionConfig, got "
                f"{type(attention_config).__name__}."
            )

    @staticmethod
    def _validate_decoder_cross_attention_config(attention_config) -> None:
        from emperor.attention import (
            IndependentAttentionConfig,
            MixtureOfAttentionHeadsConfig,
        )

        if attention_config is None:
            return
        if not isinstance(
            attention_config,
            (IndependentAttentionConfig, MixtureOfAttentionHeadsConfig),
        ):
            raise TypeError(
                "cross_attention_config must be an IndependentAttentionConfig, "
                "MixtureOfAttentionHeadsConfig, or None; MixerAttentionConfig "
                "is self-processing only. Got "
                f"{type(attention_config).__name__}."
            )

    @staticmethod
    def _validate_layer_norm_position(layer_norm_position) -> None:
        from emperor.layers import LayerNormPositionOptions

        if not isinstance(layer_norm_position, LayerNormPositionOptions):
            raise TypeError(
                "layer_norm_position must be a LayerNormPositionOptions value, "
                f"got {type(layer_norm_position).__name__}"
            )

    @staticmethod
    def _validate_residual_history_bridge(residual_config, *, owner_name: str) -> None:
        from emperor.layers import AttentionResidualConfig

        if not isinstance(residual_config, AttentionResidualConfig):
            return
        raise ValueError(
            f"AttentionResidualConfig is not supported for {owner_name} until "
            "Transformer sublayers share an explicit forward-local history bridge."
        )

    @staticmethod
    def _validate_soft_moe_attention(feed_forward_config, *attention_configs) -> None:
        from emperor.experts import SoftMoEConfig

        if not any(
            isinstance(visit.config, SoftMoEConfig)
            for visit in _configuration_visits(feed_forward_config, "feed_forward")
        ):
            return
        for config in attention_configs:
            if config is None:
                continue
            if getattr(config, "causal_attention_mask_flag", False):
                raise ValueError(
                    "Soft MoE is noncausal and cannot follow causal attention."
                )
            if not isinstance(getattr(config, "batch_first_flag", None), bool):
                raise ValueError(
                    "Soft MoE requires explicit batch_first_flag on attention."
                )

    @staticmethod
    def _validate_soft_moe_masks(model, attention_mask, cross_attention_mask) -> None:
        if not getattr(
            getattr(model, "feed_forward_model", None), "uses_soft_moe", False
        ):
            return
        attention_models = (
            model.self_attention_model,
            getattr(model, "cross_attention_model", None),
        )
        if (
            attention_mask is not None
            or cross_attention_mask is not None
            or any(
                getattr(attention, "causal_attention_mask_flag", False)
                for attention in attention_models
            )
        ):
            raise ValueError(
                "Soft MoE is noncausal; causal or explicitly masked attention is unsupported."
            )

    @staticmethod
    def _validate_feed_forward_grouping(
        feed_forward_config,
        *,
        owner_name: str,
    ) -> None:
        from emperor.augmentations.adaptive_parameters import (
            AdaptiveParameterGroupingScopeOptions,
        )

        grouping_path = _first_adaptive_grouping_path(
            feed_forward_config,
            root=f"{owner_name}.feed_forward_config",
            direct_only=True,
            predicate=lambda config: (
                config.grouping_config.scope
                is AdaptiveParameterGroupingScopeOptions.ROWS
            ),
        )
        if grouping_path is None:
            return
        raise ValueError(
            f"{owner_name} feed-forward does not support ROWS adaptive parameter "
            "grouping; use SEQUENCE for token inputs or grouping_config=None. Found grouping "
            f"at {grouping_path}."
        )

    @classmethod
    def validate_grouped_consumers(
        cls,
        model,
        hidden,
        padding_mask,
        attention_mask,
        cross_attention_mask=None,
        *,
        encoder_output=None,
        encoder_padding_mask=None,
    ) -> None:
        cls._validate_soft_moe_masks(model, attention_mask, cross_attention_mask)
        consumers = (model.cfg.feed_forward_config, model.cfg.residual_config)
        root = type(model.cfg).__name__
        if not tuple(_adaptive_grouping_configs(consumers, root=root)):
            return
        attention_model = model.self_attention_model
        batch_first = getattr(attention_model, "batch_first_flag", None)
        if batch_first is None:
            batch_first = hidden.dim() == 3 and hidden.size(1) != getattr(
                attention_model, "batch_size", None
            )
        order = "BATCH_FIRST" if batch_first else "SEQUENCE_FIRST"
        sequence_length = hidden.size(0)
        if hidden.dim() == 3 and batch_first:
            sequence_length = hidden.size(1)
        cls._validate_grouping_masks(
            attention_model, hidden, padding_mask, attention_mask
        )
        cross_model = getattr(model, "cross_attention_model", None)
        if cross_model is not None:
            cls._validate_grouping_masks(
                cross_model,
                hidden,
                encoder_padding_mask,
                cross_attention_mask,
                source_hidden=encoder_output,
            )
        _validate_adaptive_sequence_input(
            consumers, root=root, sequence_length=sequence_length, input_order=order
        )
        if padding_mask is not None:
            excluded = (
                padding_mask
                if padding_mask.dtype == torch.bool
                else padding_mask.isneginf()
            )
            if excluded.any():
                raise ValueError(
                    "Adaptive grouping requires all-valid inputs; target padding mask excludes positions."
                )
        if (
            attention_mask is not None
            or bool(getattr(attention_model, "causal_attention_mask_flag", False))
            or (
                cross_model is not None
                and (
                    cross_attention_mask is not None
                    or bool(getattr(cross_model, "causal_attention_mask_flag", False))
                )
            )
        ):
            raise ValueError(
                "Adaptive grouping context sharing is restricted after causal or explicitly masked attention."
            )

    @staticmethod
    def _validate_grouping_masks(
        attention_model,
        hidden,
        padding_mask,
        attention_mask,
        *,
        source_hidden=None,
    ) -> None:
        from emperor.attention import SelfAttentionConfig

        attention_validator = SelfAttentionConfig().registry_owner().VALIDATOR

        batch_first = getattr(attention_model, "batch_first_flag", None)
        if batch_first is None:
            batch_first = hidden.dim() == 3 and hidden.size(1) != getattr(
                attention_model, "batch_size", None
            )
        length = hidden.size(0)
        if hidden.dim() == 3 and batch_first:
            length = hidden.size(1)

        source_length = length
        if source_hidden is not None:
            source_length = source_hidden.size(0)
            if source_hidden.dim() == 3 and batch_first:
                source_length = source_hidden.size(1)
        batch = hidden.size(0 if batch_first else 1) if hidden.dim() == 3 else 1
        prepared_padding = padding_mask
        if padding_mask is not None and hidden.dim() == 2:
            prepared_padding = padding_mask.unsqueeze(0)
        attention_validator.validate_mask_shapes(
            prepared_padding,
            attention_mask,
            expected_key_padding_shape=(batch, source_length),
            expected_attention_sequence_shape=(length, source_length),
            standard_branch_count=batch * getattr(attention_model, "num_heads", 1),
        )
        for name, mask in (
            ("key_padding_mask", padding_mask),
            ("attention_mask", attention_mask),
        ):
            if mask is not None:
                attention_validator.validate_mask_is_float_or_bool(mask, name)

    # --- forward-boundary validation ---

    @classmethod
    def validate_encoder_layer_forward_inputs(
        cls,
        model: "TransformerEncoderLayer",
        source_token_embeddings: "Tensor",
        source_key_padding_mask: "Tensor | None" = None,
    ) -> None:
        cls._validate_last_dim(
            source_token_embeddings, model.embedding_dim, "source_token_embeddings"
        )
        cls._validate_transformer_key_padding_mask_shape(
            source_token_embeddings,
            source_key_padding_mask,
            model.self_attention_model,
        )

    @classmethod
    def validate_decoder_layer_forward_inputs(
        cls,
        model: "TransformerDecoderLayer",
        target_token_embeddings: "Tensor",
        encoder_output: "Tensor | None",
        target_key_padding_mask: "Tensor | None" = None,
    ) -> None:
        cls._validate_last_dim(
            target_token_embeddings, model.embedding_dim, "target_token_embeddings"
        )
        cls._validate_transformer_key_padding_mask_shape(
            target_token_embeddings,
            target_key_padding_mask,
            model.self_attention_model,
        )
        if model.cross_attention_model is None:
            return
        if encoder_output is None:
            raise ValueError(
                "TransformerDecoderLayer with cross-attention requires "
                "encoder_output, received None."
            )
        cls._validate_last_dim(encoder_output, model.embedding_dim, "encoder_output")

    @staticmethod
    def validate_transformer_forward_inputs(
        model: "Transformer",
        source_token_embeddings: "Tensor | None",
        target_token_embeddings: "Tensor | None",
    ) -> None:
        if model.encoder_model is not None and source_token_embeddings is None:
            raise ValueError(
                "Transformer with an encoder requires source_token_embeddings, "
                "received None."
            )
        if model.decoder_model is not None and target_token_embeddings is None:
            raise ValueError(
                "Transformer with a decoder requires target_token_embeddings, "
                "received None."
            )

    @staticmethod
    def _validate_last_dim(
        tensor: "Tensor | None",
        expected_dim: int,
        name: str,
    ) -> None:
        if tensor is None:
            raise ValueError(f"{name} is required, received None.")
        if tensor.size(-1) != expected_dim:
            raise ValueError(
                f"{name} last dimension must be {expected_dim}, received "
                f"{tensor.size(-1)}."
            )

    @staticmethod
    def _validate_transformer_key_padding_mask_shape(
        hidden: "Tensor",
        key_padding_mask: "Tensor | None",
        attention_model,
    ) -> None:
        if key_padding_mask is None:
            return
        if hidden.dim() != 3:
            expected_shape = (hidden.size(0),)
        else:
            batch_first_flag = getattr(attention_model, "batch_first_flag", None)
            if batch_first_flag is None:
                configured_batch_size = getattr(attention_model, "batch_size", None)
                batch_first_flag = hidden.size(1) != configured_batch_size
            batch_axis = 0 if batch_first_flag else 1
            sequence_axis = 1 if batch_first_flag else 0
            expected_shape = (
                hidden.size(batch_axis),
                hidden.size(sequence_axis),
            )
        if tuple(key_padding_mask.shape) != expected_shape:
            raise RuntimeError(
                f"key_padding_mask must have shape {expected_shape}, got "
                f"{tuple(key_padding_mask.shape)}."
            )


class SwiGLUFeedForwardValidator:
    @staticmethod
    def validate_config(cfg):
        from emperor.transformer._feed_forward import SwiGLUFeedForwardConfig

        if not isinstance(cfg, SwiGLUFeedForwardConfig):
            raise TypeError("cfg must be SwiGLUFeedForwardConfig")
        for name in ("input_dim", "output_dim", "hidden_dim"):
            value = getattr(cfg, name)
            if type(value) is not int or value <= 0:
                raise ValueError(f"{name} must be a positive integer")

    @staticmethod
    def validate_input(features, input_dim):
        if (
            not isinstance(features, torch.Tensor)
            or features.ndim < 2
            or not features.is_floating_point()
            or features.shape[-1] != input_dim
        ):
            raise ValueError(
                "SwiGLU requires floating features with the configured input width"
            )


class FeedForwardValidator(ValidatorBase):
    @staticmethod
    def uses_soft_moe(config) -> bool:
        from emperor.experts import SoftMoEConfig

        return any(
            isinstance(visit.config, SoftMoEConfig)
            for visit in _configuration_visits(config, "FeedForward")
        )

    @classmethod
    def validate(cls, model: "FeedForward") -> None:
        cls.validate_required_fields(model.cfg)
        cls.validate_dimensions(input_dim=model.input_dim, output_dim=model.output_dim)
        cls._validate_stack_config_type(model.stack_config)
        cls._validate_mirrorable_stack_topology(model.stack_config)
        if cls.uses_soft_moe(model.stack_config):
            from emperor.experts import MixtureOfExpertsModelConfig

            if not isinstance(model.stack_config, MixtureOfExpertsModelConfig):
                raise ValueError(
                    "Soft MoE FeedForward requires a direct MixtureOfExpertsModelConfig, preserving sequence and mask ownership."
                )
        _validate_grouped_row_preservation(
            model.stack_config, root="FeedForward.stack_config"
        )

    @staticmethod
    def _validate_stack_config_type(stack_config: ConfigBase) -> None:
        from emperor.experts import MixtureOfExpertsModelConfig
        from emperor.layers import LayerStackConfig, RecurrentCompositionConfig

        if not isinstance(
            stack_config,
            (
                LayerStackConfig,
                MixtureOfExpertsModelConfig,
                RecurrentCompositionConfig,
            ),
        ):
            raise TypeError(
                "FeedForward.stack_config must be a LayerStackConfig, "
                "MixtureOfExpertsModelConfig, or RecurrentCompositionConfig, got "
                f"{type(stack_config).__name__}"
            )

    @classmethod
    def _validate_mirrorable_stack_topology(cls, stack_config: ConfigBase) -> None:
        from emperor.experts import MixtureOfExpertsModelConfig
        from emperor.layers import LayerStackConfig, RecurrentCompositionConfig

        if isinstance(stack_config, LayerStackConfig):
            return
        if isinstance(stack_config, MixtureOfExpertsModelConfig):
            cls._validate_mirrorable_stack_topology(stack_config.stack_config)
            return
        elif isinstance(stack_config, RecurrentCompositionConfig):
            if stack_config._missing_transition_config_fields():
                raise TypeError(
                    "FeedForward cannot mirror stack_config of type NoneType."
                )
            for transition_config in stack_config._transition_configs():
                cls._validate_mirrorable_stack_topology(transition_config)
            return
        else:
            raise TypeError(
                "FeedForward cannot mirror stack_config of type "
                f"{type(stack_config).__name__}."
            )

    @classmethod
    def validate_forward_inputs(
        cls, model: "FeedForward", input_batch: "Tensor"
    ) -> None:
        if cls.uses_soft_moe(model.stack_config):
            if (
                not isinstance(input_batch, torch.Tensor)
                or input_batch.ndim != 3
                or input_batch.size(-1) != model.input_dim
            ):
                raise ValueError(
                    "Soft MoE FeedForward requires rank-three sequence input with the configured feature dimension."
                )
            return
        grouped = tuple(
            _adaptive_grouping_configs(
                model.stack_config, root="FeedForward.stack_config"
            )
        )
        if not grouped:
            return
        if input_batch.dim() not in (2, 3):
            raise ValueError(
                "Grouped FeedForward requires rank-two or rank-three input."
            )
        if input_batch.size(-1) != model.input_dim:
            raise ValueError(
                "Grouped FeedForward input feature dimension must match input_dim."
            )
        if input_batch.dim() == 2:
            return
        direct_grouped = tuple(
            _adaptive_grouping_configs(
                model.stack_config, root="FeedForward.stack_config", direct_only=True
            )
        )
        if not direct_grouped:
            return
        order = direct_grouped[0][1].grouping_config.input_order
        if order is None:
            raise ValueError("Rank-three FeedForward requires SEQUENCE grouping.")
        sequence_length = input_batch.size(1 if order.name == "BATCH_FIRST" else 0)
        _validate_adaptive_sequence_input(
            model.stack_config,
            root="FeedForward.stack_config",
            sequence_length=sequence_length,
            input_order=order.name,
        )

    @staticmethod
    def validate_soft_layout(inputs, padding_mask, batch_first) -> None:
        if not isinstance(batch_first, bool):
            raise TypeError("Soft MoE batch_first must be Boolean.")
        if padding_mask is None:
            return
        expected = inputs.shape[:2] if batch_first else (inputs.size(1), inputs.size(0))
        if (
            not isinstance(padding_mask, torch.Tensor)
            or padding_mask.shape != expected
            or padding_mask.device != inputs.device
        ):
            raise ValueError(
                "Soft MoE padding_mask must have shape [batch, tokens] on the input device."
            )
        if padding_mask.dtype != torch.bool:
            if not padding_mask.is_floating_point():
                raise TypeError(
                    "Soft MoE padding_mask must be Boolean or additive floating point."
                )
            if (padding_mask.isnan() | padding_mask.isposinf()).any():
                raise ValueError(
                    "Soft MoE additive padding masks cannot contain NaN or positive infinity."
                )
