from enum import Enum, auto
from types import ModuleType

from models.vit.linear_adaptive.runtime_options import (
    AdaptiveGeneratorStackOptions,
    AdaptiveGeneratorStackSource,
    DynamicMemoryOptions,
    HiddenAdaptiveBiasOptions,
    HiddenAdaptiveDiagonalOptions,
    HiddenAdaptiveMaskOptions,
    HiddenAdaptiveWeightOptions,
    LayerControllerOptions,
    MainLayerStackOptions,
    RecurrentControllerOptions,
    SubmoduleStackOptions,
    SubmoduleStackSource,
    TransformerAttentionOptions,
    TransformerEncoderOptions,
    TransformerFeedForwardOptions,
    TransformerPositionalEmbeddingOptions,
    VitOutputOptions,
    VitPatchOptions,
)


class LinearRole(Enum):
    MAIN = auto()
    ATTENTION = auto()
    FEED_FORWARD = auto()


class AdaptiveRole(Enum):
    MAIN = auto()
    ATTENTION = auto()
    FEED_FORWARD = auto()


class AdaptiveParameter(Enum):
    WEIGHT = auto()
    BIAS = auto()
    DIAGONAL = auto()
    MASK = auto()


class _ControllerStackRole(Enum):
    GATE = auto()
    HALTING = auto()
    MEMORY = auto()
    RECURRENT_GATE = auto()
    RECURRENT_HALTING = auto()


def vit_patch_options(config: ModuleType) -> VitPatchOptions:
    return VitPatchOptions(
        patch_size=config.IMAGE_PATCH_SIZE,
        input_channels=config.INPUT_CHANNELS,
        image_height=config.IMAGE_HEIGHT,
        dropout_probability=config.PATCH_DROPOUT_PROBABILITY,
        bias_flag=config.PATCH_BIAS_FLAG,
    )


def vit_positional_embedding_options(
    config: ModuleType,
) -> TransformerPositionalEmbeddingOptions:
    return TransformerPositionalEmbeddingOptions(
        option=config.POSITIONAL_EMBEDDING_OPTION,
        padding_idx=config.POSITIONAL_EMBEDDING_PADDING_IDX,
        auto_expand_flag=config.POSITIONAL_EMBEDDING_AUTO_EXPAND_FLAG,
    )


def vit_encoder_options(config: ModuleType) -> TransformerEncoderOptions:
    return TransformerEncoderOptions(
        hidden_dim=config.HIDDEN_DIM,
        num_layers=config.STACK_NUM_LAYERS,
        activation=config.STACK_ACTIVATION,
        dropout_probability=config.STACK_DROPOUT_PROBABILITY,
        layer_norm_position=config.LAYER_NORM_POSITION,
        normalization=config.NORMALIZATION,
        causal_attention_mask_flag=False,
        output_normalization=config.ENCODER_OUTPUT_NORMALIZATION,
    )


def vit_attention_options(config: ModuleType) -> TransformerAttentionOptions:
    return TransformerAttentionOptions(
        num_heads=config.ATTN_NUM_HEADS,
        num_layers=config.ATTN_NUM_LAYERS,
        bias_flag=config.ATTN_BIAS_FLAG,
        add_key_value_bias_flag=config.ATTN_ADD_KEY_VALUE_BIAS_FLAG,
        source_memory_flag=config.ATTN_SOURCE_MEMORY_FLAG,
        source_memory_option=config.ATTN_SOURCE_MEMORY_OPTION,
        source_memory_num_memory_slots=config.ATTN_SOURCE_MEMORY_NUM_MEMORY_SLOTS,
        source_memory_test_time_training_learning_rate=config.ATTN_SOURCE_MEMORY_TEST_TIME_TRAINING_LEARNING_RATE,
        source_memory_test_time_training_num_inner_steps=config.ATTN_SOURCE_MEMORY_TEST_TIME_TRAINING_NUM_INNER_STEPS,
    )


def vit_feed_forward_options(config: ModuleType) -> TransformerFeedForwardOptions:
    return TransformerFeedForwardOptions(
        num_layers=config.FF_NUM_LAYERS,
        bias_flag=config.FF_BIAS_FLAG,
    )


def vit_output_options(config: ModuleType) -> VitOutputOptions:
    return VitOutputOptions(bias_flag=config.OUTPUT_BIAS_FLAG)


def main_layer_stack_options(config: ModuleType) -> MainLayerStackOptions:
    return MainLayerStackOptions(
        bias_flag=config.STACK_BIAS_FLAG,
        layer_norm_position=config.LAYER_NORM_POSITION,
        normalization=config.NORMALIZATION,
        num_layers=config.STACK_NUM_LAYERS,
        activation=config.STACK_ACTIVATION,
        residual_connection_option=config.STACK_RESIDUAL_CONNECTION_OPTION,
        residual_block_size=config.STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.STACK_DROPOUT_PROBABILITY,
        last_layer_bias_option=config.STACK_LAST_LAYER_BIAS_OPTION,
        apply_output_postprocessing_flag=config.STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG,
    )


def linears_submodule_stack_options(
    config: ModuleType,
    role: LinearRole,
) -> SubmoduleStackOptions:
    if role is LinearRole.MAIN:
        return SubmoduleStackOptions(
            hidden_dim=config.SUBMODULE_STACK_HIDDEN_DIM,
            num_layers=config.SUBMODULE_STACK_NUM_LAYERS,
            last_layer_bias_option=config.SUBMODULE_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=(
                config.SUBMODULE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            activation=config.SUBMODULE_STACK_ACTIVATION,
            layer_norm_position=config.SUBMODULE_STACK_LAYER_NORM_POSITION,
            normalization=config.SUBMODULE_STACK_NORMALIZATION,
            residual_connection_option=(
                config.SUBMODULE_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.SUBMODULE_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.SUBMODULE_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.SUBMODULE_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.SUBMODULE_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.SUBMODULE_STACK_BIAS_FLAG,
        )
    if role is LinearRole.ATTENTION:
        return SubmoduleStackOptions(
            hidden_dim=config.ATTN_STACK_HIDDEN_DIM,
            num_layers=config.ATTN_NUM_LAYERS,
            last_layer_bias_option=config.ATTN_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=config.ATTN_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG,
            activation=config.ATTN_STACK_ACTIVATION,
            layer_norm_position=config.ATTN_STACK_LAYER_NORM_POSITION,
            normalization=config.ATTN_STACK_NORMALIZATION,
            residual_connection_option=config.ATTN_STACK_RESIDUAL_CONNECTION_OPTION,
            residual_block_size=config.ATTN_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.ATTN_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.ATTN_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.ATTN_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.ATTN_BIAS_FLAG,
        )
    return SubmoduleStackOptions(
        hidden_dim=config.FF_STACK_HIDDEN_DIM,
        num_layers=config.FF_NUM_LAYERS,
        last_layer_bias_option=config.FF_STACK_LAST_LAYER_BIAS_OPTION,
        apply_output_postprocessing_flag=config.FF_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG,
        activation=config.FF_STACK_ACTIVATION,
        layer_norm_position=config.FF_STACK_LAYER_NORM_POSITION,
        normalization=config.FF_STACK_NORMALIZATION,
        residual_connection_option=config.FF_STACK_RESIDUAL_CONNECTION_OPTION,
        residual_block_size=config.FF_STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.FF_STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.FF_STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.FF_STACK_DROPOUT_PROBABILITY,
        bias_flag=config.FF_BIAS_FLAG,
    )


def _controller_stack_source(
    config: ModuleType,
    role: LinearRole,
    stack_role: _ControllerStackRole,
) -> SubmoduleStackSource:
    if role is LinearRole.MAIN:
        return _main_controller_stack_source(config, stack_role)
    if role is LinearRole.ATTENTION:
        return _attention_controller_stack_source(config, stack_role)
    return _feed_forward_controller_stack_source(config, stack_role)


def _main_controller_stack_source(
    config: ModuleType,
    stack_role: _ControllerStackRole,
) -> SubmoduleStackSource:
    if stack_role is _ControllerStackRole.GATE:
        return SubmoduleStackSource(
            independent_flag=config.GATE_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.GATE_STACK_HIDDEN_DIM,
            num_layers=config.GATE_STACK_NUM_LAYERS,
            last_layer_bias_option=config.GATE_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=config.GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG,
            activation=config.GATE_STACK_ACTIVATION,
            layer_norm_position=config.GATE_STACK_LAYER_NORM_POSITION,
            normalization=config.GATE_STACK_NORMALIZATION,
            residual_connection_option=config.GATE_STACK_RESIDUAL_CONNECTION_OPTION,
            residual_block_size=config.GATE_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.GATE_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.GATE_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.GATE_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.GATE_STACK_BIAS_FLAG,
        )
    if stack_role is _ControllerStackRole.HALTING:
        return SubmoduleStackSource(
            independent_flag=config.HALTING_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.HALTING_STACK_HIDDEN_DIM,
            num_layers=config.HALTING_STACK_NUM_LAYERS,
            last_layer_bias_option=config.HALTING_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=(
                config.HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            activation=config.HALTING_STACK_ACTIVATION,
            layer_norm_position=config.HALTING_STACK_LAYER_NORM_POSITION,
            normalization=config.HALTING_STACK_NORMALIZATION,
            residual_connection_option=(
                config.HALTING_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.HALTING_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.HALTING_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.HALTING_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.HALTING_STACK_BIAS_FLAG,
        )
    if stack_role is _ControllerStackRole.MEMORY:
        return SubmoduleStackSource(
            independent_flag=config.MEMORY_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.MEMORY_STACK_HIDDEN_DIM,
            num_layers=config.MEMORY_STACK_NUM_LAYERS,
            last_layer_bias_option=config.MEMORY_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=config.MEMORY_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG,
            activation=config.MEMORY_STACK_ACTIVATION,
            layer_norm_position=config.MEMORY_STACK_LAYER_NORM_POSITION,
            normalization=config.MEMORY_STACK_NORMALIZATION,
            residual_connection_option=config.MEMORY_STACK_RESIDUAL_CONNECTION_OPTION,
            residual_block_size=config.MEMORY_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.MEMORY_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.MEMORY_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.MEMORY_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.MEMORY_STACK_BIAS_FLAG,
        )
    if stack_role is _ControllerStackRole.RECURRENT_GATE:
        return SubmoduleStackSource(
            independent_flag=config.RECURRENT_GATE_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.RECURRENT_GATE_STACK_HIDDEN_DIM,
            num_layers=config.RECURRENT_GATE_STACK_NUM_LAYERS,
            last_layer_bias_option=(config.RECURRENT_GATE_STACK_LAST_LAYER_BIAS_OPTION),
            apply_output_postprocessing_flag=(
                config.RECURRENT_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            activation=config.RECURRENT_GATE_STACK_ACTIVATION,
            layer_norm_position=config.RECURRENT_GATE_STACK_LAYER_NORM_POSITION,
            normalization=config.RECURRENT_GATE_STACK_NORMALIZATION,
            residual_connection_option=(
                config.RECURRENT_GATE_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.RECURRENT_GATE_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.RECURRENT_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.RECURRENT_GATE_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.RECURRENT_GATE_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.RECURRENT_GATE_STACK_BIAS_FLAG,
        )
    return SubmoduleStackSource(
        independent_flag=config.RECURRENT_HALTING_STACK_INDEPENDENT_FLAG,
        hidden_dim=config.RECURRENT_HALTING_STACK_HIDDEN_DIM,
        num_layers=config.RECURRENT_HALTING_STACK_NUM_LAYERS,
        last_layer_bias_option=(config.RECURRENT_HALTING_STACK_LAST_LAYER_BIAS_OPTION),
        apply_output_postprocessing_flag=(
            config.RECURRENT_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
        ),
        activation=config.RECURRENT_HALTING_STACK_ACTIVATION,
        layer_norm_position=config.RECURRENT_HALTING_STACK_LAYER_NORM_POSITION,
        normalization=config.RECURRENT_HALTING_STACK_NORMALIZATION,
        residual_connection_option=(
            config.RECURRENT_HALTING_STACK_RESIDUAL_CONNECTION_OPTION
        ),
        residual_block_size=config.RECURRENT_HALTING_STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.RECURRENT_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.RECURRENT_HALTING_STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.RECURRENT_HALTING_STACK_DROPOUT_PROBABILITY,
        bias_flag=config.RECURRENT_HALTING_STACK_BIAS_FLAG,
    )


def _attention_controller_stack_source(
    config: ModuleType,
    stack_role: _ControllerStackRole,
) -> SubmoduleStackSource:
    if stack_role is _ControllerStackRole.GATE:
        return SubmoduleStackSource(
            independent_flag=config.ATTN_GATE_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.ATTN_GATE_STACK_HIDDEN_DIM,
            num_layers=config.ATTN_GATE_STACK_NUM_LAYERS,
            last_layer_bias_option=config.ATTN_GATE_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=(
                config.ATTN_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            activation=config.ATTN_GATE_STACK_ACTIVATION,
            layer_norm_position=config.ATTN_GATE_STACK_LAYER_NORM_POSITION,
            normalization=config.ATTN_GATE_STACK_NORMALIZATION,
            residual_connection_option=(
                config.ATTN_GATE_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.ATTN_GATE_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.ATTN_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.ATTN_GATE_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.ATTN_GATE_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.ATTN_GATE_STACK_BIAS_FLAG,
        )
    if stack_role is _ControllerStackRole.HALTING:
        return SubmoduleStackSource(
            independent_flag=config.ATTN_HALTING_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.ATTN_HALTING_STACK_HIDDEN_DIM,
            num_layers=config.ATTN_HALTING_STACK_NUM_LAYERS,
            last_layer_bias_option=config.ATTN_HALTING_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=(
                config.ATTN_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            activation=config.ATTN_HALTING_STACK_ACTIVATION,
            layer_norm_position=config.ATTN_HALTING_STACK_LAYER_NORM_POSITION,
            normalization=config.ATTN_HALTING_STACK_NORMALIZATION,
            residual_connection_option=(
                config.ATTN_HALTING_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.ATTN_HALTING_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.ATTN_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.ATTN_HALTING_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.ATTN_HALTING_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.ATTN_HALTING_STACK_BIAS_FLAG,
        )
    if stack_role is _ControllerStackRole.MEMORY:
        return SubmoduleStackSource(
            independent_flag=config.ATTN_MEMORY_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.ATTN_MEMORY_STACK_HIDDEN_DIM,
            num_layers=config.ATTN_MEMORY_STACK_NUM_LAYERS,
            last_layer_bias_option=config.ATTN_MEMORY_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=(
                config.ATTN_MEMORY_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            activation=config.ATTN_MEMORY_STACK_ACTIVATION,
            layer_norm_position=config.ATTN_MEMORY_STACK_LAYER_NORM_POSITION,
            normalization=config.ATTN_MEMORY_STACK_NORMALIZATION,
            residual_connection_option=(
                config.ATTN_MEMORY_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.ATTN_MEMORY_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.ATTN_MEMORY_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.ATTN_MEMORY_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.ATTN_MEMORY_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.ATTN_MEMORY_STACK_BIAS_FLAG,
        )
    if stack_role is _ControllerStackRole.RECURRENT_GATE:
        return SubmoduleStackSource(
            independent_flag=config.ATTN_RECURRENT_GATE_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.ATTN_RECURRENT_GATE_STACK_HIDDEN_DIM,
            num_layers=config.ATTN_RECURRENT_GATE_STACK_NUM_LAYERS,
            last_layer_bias_option=(
                config.ATTN_RECURRENT_GATE_STACK_LAST_LAYER_BIAS_OPTION
            ),
            apply_output_postprocessing_flag=(
                config.ATTN_RECURRENT_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            activation=config.ATTN_RECURRENT_GATE_STACK_ACTIVATION,
            layer_norm_position=config.ATTN_RECURRENT_GATE_STACK_LAYER_NORM_POSITION,
            normalization=config.ATTN_RECURRENT_GATE_STACK_NORMALIZATION,
            residual_connection_option=(
                config.ATTN_RECURRENT_GATE_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.ATTN_RECURRENT_GATE_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.ATTN_RECURRENT_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.ATTN_RECURRENT_GATE_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=(config.ATTN_RECURRENT_GATE_STACK_DROPOUT_PROBABILITY),
            bias_flag=config.ATTN_RECURRENT_GATE_STACK_BIAS_FLAG,
        )
    return SubmoduleStackSource(
        independent_flag=config.ATTN_RECURRENT_HALTING_STACK_INDEPENDENT_FLAG,
        hidden_dim=config.ATTN_RECURRENT_HALTING_STACK_HIDDEN_DIM,
        num_layers=config.ATTN_RECURRENT_HALTING_STACK_NUM_LAYERS,
        last_layer_bias_option=(
            config.ATTN_RECURRENT_HALTING_STACK_LAST_LAYER_BIAS_OPTION
        ),
        apply_output_postprocessing_flag=(
            config.ATTN_RECURRENT_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
        ),
        activation=config.ATTN_RECURRENT_HALTING_STACK_ACTIVATION,
        layer_norm_position=config.ATTN_RECURRENT_HALTING_STACK_LAYER_NORM_POSITION,
        normalization=config.ATTN_RECURRENT_HALTING_STACK_NORMALIZATION,
        residual_connection_option=(
            config.ATTN_RECURRENT_HALTING_STACK_RESIDUAL_CONNECTION_OPTION
        ),
        residual_block_size=config.ATTN_RECURRENT_HALTING_STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.ATTN_RECURRENT_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.ATTN_RECURRENT_HALTING_STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.ATTN_RECURRENT_HALTING_STACK_DROPOUT_PROBABILITY,
        bias_flag=config.ATTN_RECURRENT_HALTING_STACK_BIAS_FLAG,
    )


def _feed_forward_controller_stack_source(
    config: ModuleType,
    stack_role: _ControllerStackRole,
) -> SubmoduleStackSource:
    if stack_role is _ControllerStackRole.GATE:
        return SubmoduleStackSource(
            independent_flag=config.FF_GATE_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.FF_GATE_STACK_HIDDEN_DIM,
            num_layers=config.FF_GATE_STACK_NUM_LAYERS,
            last_layer_bias_option=config.FF_GATE_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=(
                config.FF_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            activation=config.FF_GATE_STACK_ACTIVATION,
            layer_norm_position=config.FF_GATE_STACK_LAYER_NORM_POSITION,
            normalization=config.FF_GATE_STACK_NORMALIZATION,
            residual_connection_option=(
                config.FF_GATE_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.FF_GATE_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.FF_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.FF_GATE_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.FF_GATE_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.FF_GATE_STACK_BIAS_FLAG,
        )
    if stack_role is _ControllerStackRole.HALTING:
        return SubmoduleStackSource(
            independent_flag=config.FF_HALTING_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.FF_HALTING_STACK_HIDDEN_DIM,
            num_layers=config.FF_HALTING_STACK_NUM_LAYERS,
            last_layer_bias_option=config.FF_HALTING_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=(
                config.FF_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            activation=config.FF_HALTING_STACK_ACTIVATION,
            layer_norm_position=config.FF_HALTING_STACK_LAYER_NORM_POSITION,
            normalization=config.FF_HALTING_STACK_NORMALIZATION,
            residual_connection_option=(
                config.FF_HALTING_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.FF_HALTING_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.FF_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.FF_HALTING_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.FF_HALTING_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.FF_HALTING_STACK_BIAS_FLAG,
        )
    if stack_role is _ControllerStackRole.MEMORY:
        return SubmoduleStackSource(
            independent_flag=config.FF_MEMORY_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.FF_MEMORY_STACK_HIDDEN_DIM,
            num_layers=config.FF_MEMORY_STACK_NUM_LAYERS,
            last_layer_bias_option=config.FF_MEMORY_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=(
                config.FF_MEMORY_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            activation=config.FF_MEMORY_STACK_ACTIVATION,
            layer_norm_position=config.FF_MEMORY_STACK_LAYER_NORM_POSITION,
            normalization=config.FF_MEMORY_STACK_NORMALIZATION,
            residual_connection_option=(
                config.FF_MEMORY_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.FF_MEMORY_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.FF_MEMORY_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.FF_MEMORY_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.FF_MEMORY_STACK_DROPOUT_PROBABILITY,
            bias_flag=config.FF_MEMORY_STACK_BIAS_FLAG,
        )
    if stack_role is _ControllerStackRole.RECURRENT_GATE:
        return SubmoduleStackSource(
            independent_flag=config.FF_RECURRENT_GATE_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.FF_RECURRENT_GATE_STACK_HIDDEN_DIM,
            num_layers=config.FF_RECURRENT_GATE_STACK_NUM_LAYERS,
            last_layer_bias_option=(
                config.FF_RECURRENT_GATE_STACK_LAST_LAYER_BIAS_OPTION
            ),
            apply_output_postprocessing_flag=(
                config.FF_RECURRENT_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            activation=config.FF_RECURRENT_GATE_STACK_ACTIVATION,
            layer_norm_position=config.FF_RECURRENT_GATE_STACK_LAYER_NORM_POSITION,
            normalization=config.FF_RECURRENT_GATE_STACK_NORMALIZATION,
            residual_connection_option=(
                config.FF_RECURRENT_GATE_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.FF_RECURRENT_GATE_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.FF_RECURRENT_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.FF_RECURRENT_GATE_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=(config.FF_RECURRENT_GATE_STACK_DROPOUT_PROBABILITY),
            bias_flag=config.FF_RECURRENT_GATE_STACK_BIAS_FLAG,
        )
    return SubmoduleStackSource(
        independent_flag=config.FF_RECURRENT_HALTING_STACK_INDEPENDENT_FLAG,
        hidden_dim=config.FF_RECURRENT_HALTING_STACK_HIDDEN_DIM,
        num_layers=config.FF_RECURRENT_HALTING_STACK_NUM_LAYERS,
        last_layer_bias_option=(
            config.FF_RECURRENT_HALTING_STACK_LAST_LAYER_BIAS_OPTION
        ),
        apply_output_postprocessing_flag=(
            config.FF_RECURRENT_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
        ),
        activation=config.FF_RECURRENT_HALTING_STACK_ACTIVATION,
        layer_norm_position=config.FF_RECURRENT_HALTING_STACK_LAYER_NORM_POSITION,
        normalization=config.FF_RECURRENT_HALTING_STACK_NORMALIZATION,
        residual_connection_option=(
            config.FF_RECURRENT_HALTING_STACK_RESIDUAL_CONNECTION_OPTION
        ),
        residual_block_size=config.FF_RECURRENT_HALTING_STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.FF_RECURRENT_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.FF_RECURRENT_HALTING_STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.FF_RECURRENT_HALTING_STACK_DROPOUT_PROBABILITY,
        bias_flag=config.FF_RECURRENT_HALTING_STACK_BIAS_FLAG,
    )


def linears_layer_controller_options(
    config: ModuleType,
    role: LinearRole,
) -> LayerControllerOptions:
    if role is LinearRole.MAIN:
        return LayerControllerOptions(
            stack_gate_flag=config.STACK_GATE_FLAG,
            gate_option=config.GATE_OPTION,
            gate_activation=config.GATE_ACTIVATION,
            gate_stack_source=_controller_stack_source(
                config, role, _ControllerStackRole.GATE
            ),
            stack_halting_flag=config.STACK_HALTING_FLAG,
            halting_option=config.HALTING_OPTION,
            halting_threshold=config.HALTING_THRESHOLD,
            halting_dropout=config.HALTING_DROPOUT,
            halting_hidden_state_mode=config.HALTING_HIDDEN_STATE_MODE,
            halting_stack_source=_controller_stack_source(
                config, role, _ControllerStackRole.HALTING
            ),
        )
    if role is LinearRole.ATTENTION:
        return LayerControllerOptions(
            stack_gate_flag=config.ATTN_STACK_GATE_FLAG,
            gate_option=config.ATTN_GATE_OPTION,
            gate_activation=config.ATTN_GATE_ACTIVATION,
            gate_stack_source=_controller_stack_source(
                config, role, _ControllerStackRole.GATE
            ),
            stack_halting_flag=config.ATTN_STACK_HALTING_FLAG,
            halting_option=config.ATTN_HALTING_OPTION,
            halting_threshold=config.ATTN_HALTING_THRESHOLD,
            halting_dropout=config.ATTN_HALTING_DROPOUT,
            halting_hidden_state_mode=config.ATTN_HALTING_HIDDEN_STATE_MODE,
            halting_stack_source=_controller_stack_source(
                config, role, _ControllerStackRole.HALTING
            ),
        )
    return LayerControllerOptions(
        stack_gate_flag=config.FF_STACK_GATE_FLAG,
        gate_option=config.FF_GATE_OPTION,
        gate_activation=config.FF_GATE_ACTIVATION,
        gate_stack_source=_controller_stack_source(
            config, role, _ControllerStackRole.GATE
        ),
        stack_halting_flag=config.FF_STACK_HALTING_FLAG,
        halting_option=config.FF_HALTING_OPTION,
        halting_threshold=config.FF_HALTING_THRESHOLD,
        halting_dropout=config.FF_HALTING_DROPOUT,
        halting_hidden_state_mode=config.FF_HALTING_HIDDEN_STATE_MODE,
        halting_stack_source=_controller_stack_source(
            config, role, _ControllerStackRole.HALTING
        ),
    )


def linears_dynamic_memory_options(
    config: ModuleType,
    role: LinearRole,
) -> DynamicMemoryOptions:
    if role is LinearRole.MAIN:
        return DynamicMemoryOptions(
            memory_flag=config.MEMORY_FLAG,
            memory_option=config.MEMORY_OPTION,
            memory_position_option=config.MEMORY_POSITION_OPTION,
            memory_test_time_training_learning_rate=(
                config.MEMORY_TEST_TIME_TRAINING_LEARNING_RATE
            ),
            memory_test_time_training_num_inner_steps=(
                config.MEMORY_TEST_TIME_TRAINING_NUM_INNER_STEPS
            ),
            memory_stack_source=_controller_stack_source(
                config, role, _ControllerStackRole.MEMORY
            ),
        )
    if role is LinearRole.ATTENTION:
        return DynamicMemoryOptions(
            memory_flag=config.ATTN_MEMORY_FLAG,
            memory_option=config.ATTN_MEMORY_OPTION,
            memory_position_option=config.ATTN_MEMORY_POSITION_OPTION,
            memory_test_time_training_learning_rate=(
                config.ATTN_MEMORY_TEST_TIME_TRAINING_LEARNING_RATE
            ),
            memory_test_time_training_num_inner_steps=(
                config.ATTN_MEMORY_TEST_TIME_TRAINING_NUM_INNER_STEPS
            ),
            memory_stack_source=_controller_stack_source(
                config, role, _ControllerStackRole.MEMORY
            ),
        )
    return DynamicMemoryOptions(
        memory_flag=config.FF_MEMORY_FLAG,
        memory_option=config.FF_MEMORY_OPTION,
        memory_position_option=config.FF_MEMORY_POSITION_OPTION,
        memory_test_time_training_learning_rate=(
            config.FF_MEMORY_TEST_TIME_TRAINING_LEARNING_RATE
        ),
        memory_test_time_training_num_inner_steps=(
            config.FF_MEMORY_TEST_TIME_TRAINING_NUM_INNER_STEPS
        ),
        memory_stack_source=_controller_stack_source(
            config, role, _ControllerStackRole.MEMORY
        ),
    )


def linears_recurrent_controller_options(
    config: ModuleType,
    role: LinearRole,
) -> RecurrentControllerOptions:
    if role is LinearRole.MAIN:
        return RecurrentControllerOptions(
            recurrent_flag=config.RECURRENT_FLAG,
            recurrent_max_steps=config.RECURRENT_MAX_STEPS,
            recurrent_initial_iterations=config.RECURRENT_INITIAL_ITERATIONS,
            recurrent_gradient_transition_count=(
                config.RECURRENT_GRADIENT_TRANSITION_COUNT
            ),
            recurrent_no_gradient_transition_count=(
                config.RECURRENT_NO_GRADIENT_TRANSITION_COUNT
            ),
            recurrent_iteration_increment=config.RECURRENT_ITERATION_INCREMENT,
            recurrent_forward_calls_before_iteration_increment=(
                config.RECURRENT_FORWARD_CALLS_BEFORE_ITERATION_INCREMENT
            ),
            recurrent_smooth_iteration_growth_flag=(
                config.RECURRENT_SMOOTH_ITERATION_GROWTH_FLAG
            ),
            recurrent_layer_norm_position=config.RECURRENT_LAYER_NORM_POSITION,
            recurrent_normalization=config.RECURRENT_NORMALIZATION,
            recurrent_stack_gate_flag=config.RECURRENT_STACK_GATE_FLAG,
            recurrent_gate_option=config.RECURRENT_GATE_OPTION,
            recurrent_gate_activation=config.RECURRENT_GATE_ACTIVATION,
            recurrent_gate_stack_source=_controller_stack_source(
                config, role, _ControllerStackRole.RECURRENT_GATE
            ),
            recurrent_stack_halting_flag=config.RECURRENT_STACK_HALTING_FLAG,
            recurrent_halting_option=config.RECURRENT_HALTING_OPTION,
            recurrent_halting_threshold=config.RECURRENT_HALTING_THRESHOLD,
            recurrent_halting_dropout=config.RECURRENT_HALTING_DROPOUT,
            recurrent_halting_hidden_state_mode=(
                config.RECURRENT_HALTING_HIDDEN_STATE_MODE
            ),
            recurrent_halting_stack_source=_controller_stack_source(
                config, role, _ControllerStackRole.RECURRENT_HALTING
            ),
        )
    if role is LinearRole.ATTENTION:
        return RecurrentControllerOptions(
            recurrent_flag=config.ATTN_RECURRENT_FLAG,
            recurrent_max_steps=config.ATTN_RECURRENT_MAX_STEPS,
            recurrent_initial_iterations=2,
            recurrent_gradient_transition_count=None,
            recurrent_no_gradient_transition_count=None,
            recurrent_iteration_increment=1,
            recurrent_forward_calls_before_iteration_increment=1,
            recurrent_layer_norm_position=config.ATTN_RECURRENT_LAYER_NORM_POSITION,
            recurrent_normalization=config.ATTN_RECURRENT_NORMALIZATION,
            recurrent_stack_gate_flag=config.ATTN_RECURRENT_STACK_GATE_FLAG,
            recurrent_gate_option=config.ATTN_RECURRENT_GATE_OPTION,
            recurrent_gate_activation=config.ATTN_RECURRENT_GATE_ACTIVATION,
            recurrent_gate_stack_source=_controller_stack_source(
                config, role, _ControllerStackRole.RECURRENT_GATE
            ),
            recurrent_stack_halting_flag=config.ATTN_RECURRENT_STACK_HALTING_FLAG,
            recurrent_halting_option=config.ATTN_RECURRENT_HALTING_OPTION,
            recurrent_halting_threshold=config.ATTN_RECURRENT_HALTING_THRESHOLD,
            recurrent_halting_dropout=config.ATTN_RECURRENT_HALTING_DROPOUT,
            recurrent_halting_hidden_state_mode=(
                config.ATTN_RECURRENT_HALTING_HIDDEN_STATE_MODE
            ),
            recurrent_halting_stack_source=_controller_stack_source(
                config, role, _ControllerStackRole.RECURRENT_HALTING
            ),
        )
    return RecurrentControllerOptions(
        recurrent_flag=config.FF_RECURRENT_FLAG,
        recurrent_max_steps=config.FF_RECURRENT_MAX_STEPS,
        recurrent_initial_iterations=2,
        recurrent_gradient_transition_count=None,
        recurrent_no_gradient_transition_count=None,
        recurrent_iteration_increment=1,
        recurrent_forward_calls_before_iteration_increment=1,
        recurrent_layer_norm_position=config.FF_RECURRENT_LAYER_NORM_POSITION,
        recurrent_normalization=config.FF_RECURRENT_NORMALIZATION,
        recurrent_stack_gate_flag=config.FF_RECURRENT_STACK_GATE_FLAG,
        recurrent_gate_option=config.FF_RECURRENT_GATE_OPTION,
        recurrent_gate_activation=config.FF_RECURRENT_GATE_ACTIVATION,
        recurrent_gate_stack_source=_controller_stack_source(
            config, role, _ControllerStackRole.RECURRENT_GATE
        ),
        recurrent_stack_halting_flag=config.FF_RECURRENT_STACK_HALTING_FLAG,
        recurrent_halting_option=config.FF_RECURRENT_HALTING_OPTION,
        recurrent_halting_threshold=config.FF_RECURRENT_HALTING_THRESHOLD,
        recurrent_halting_dropout=config.FF_RECURRENT_HALTING_DROPOUT,
        recurrent_halting_hidden_state_mode=(
            config.FF_RECURRENT_HALTING_HIDDEN_STATE_MODE
        ),
        recurrent_halting_stack_source=_controller_stack_source(
            config, role, _ControllerStackRole.RECURRENT_HALTING
        ),
    )


def adaptive_generator_stack_options(
    config: ModuleType,
) -> AdaptiveGeneratorStackOptions:
    return AdaptiveGeneratorStackOptions(
        hidden_dim=config.ADAPTIVE_GENERATOR_STACK_HIDDEN_DIM,
        layer_norm_position=config.ADAPTIVE_GENERATOR_STACK_LAYER_NORM_POSITION,
        normalization=config.ADAPTIVE_GENERATOR_STACK_NORMALIZATION,
        num_layers=config.ADAPTIVE_GENERATOR_STACK_NUM_LAYERS,
        activation=config.ADAPTIVE_GENERATOR_STACK_ACTIVATION,
        residual_connection_option=config.ADAPTIVE_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION,
        residual_block_size=config.ADAPTIVE_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.ADAPTIVE_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.ADAPTIVE_GENERATOR_STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.ADAPTIVE_GENERATOR_STACK_DROPOUT_PROBABILITY,
        last_layer_bias_option=config.ADAPTIVE_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION,
        apply_output_postprocessing_flag=config.ADAPTIVE_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG,
        bias_flag=config.ADAPTIVE_GENERATOR_STACK_BIAS_FLAG,
    )


def adaptive_generator_stack_source(
    config: ModuleType,
    role: AdaptiveRole,
    parameter: AdaptiveParameter,
) -> AdaptiveGeneratorStackSource:
    if parameter is AdaptiveParameter.WEIGHT:
        return _weight_generator_stack_source(config, role)
    if parameter is AdaptiveParameter.BIAS:
        return _bias_generator_stack_source(config, role)
    if parameter is AdaptiveParameter.DIAGONAL:
        return _diagonal_generator_stack_source(config, role)
    return _mask_generator_stack_source(config, role)


def _weight_generator_stack_source(
    config: ModuleType, role: AdaptiveRole
) -> AdaptiveGeneratorStackSource:
    if role is AdaptiveRole.MAIN:
        return AdaptiveGeneratorStackSource(
            independent_flag=config.WEIGHT_GENERATOR_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.WEIGHT_GENERATOR_STACK_HIDDEN_DIM,
            layer_norm_position=config.WEIGHT_GENERATOR_STACK_LAYER_NORM_POSITION,
            normalization=config.WEIGHT_GENERATOR_STACK_NORMALIZATION,
            num_layers=config.WEIGHT_GENERATOR_STACK_NUM_LAYERS,
            activation=config.WEIGHT_GENERATOR_STACK_ACTIVATION,
            residual_connection_option=(
                config.WEIGHT_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.WEIGHT_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.WEIGHT_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.WEIGHT_GENERATOR_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.WEIGHT_GENERATOR_STACK_DROPOUT_PROBABILITY,
            last_layer_bias_option=(
                config.WEIGHT_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION
            ),
            apply_output_postprocessing_flag=(
                config.WEIGHT_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            bias_flag=config.WEIGHT_GENERATOR_STACK_BIAS_FLAG,
        )
    if role is AdaptiveRole.ATTENTION:
        return AdaptiveGeneratorStackSource(
            independent_flag=config.ATTN_WEIGHT_GENERATOR_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.ATTN_WEIGHT_GENERATOR_STACK_HIDDEN_DIM,
            layer_norm_position=(
                config.ATTN_WEIGHT_GENERATOR_STACK_LAYER_NORM_POSITION
            ),
            normalization=(config.ATTN_WEIGHT_GENERATOR_STACK_NORMALIZATION),
            num_layers=config.ATTN_WEIGHT_GENERATOR_STACK_NUM_LAYERS,
            activation=config.ATTN_WEIGHT_GENERATOR_STACK_ACTIVATION,
            residual_connection_option=(
                config.ATTN_WEIGHT_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.ATTN_WEIGHT_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.ATTN_WEIGHT_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=(
                config.ATTN_WEIGHT_GENERATOR_STACK_RESIDUAL_MODEL_FLAG
            ),
            dropout_probability=(
                config.ATTN_WEIGHT_GENERATOR_STACK_DROPOUT_PROBABILITY
            ),
            last_layer_bias_option=(
                config.ATTN_WEIGHT_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION
            ),
            apply_output_postprocessing_flag=(
                config.ATTN_WEIGHT_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            bias_flag=config.ATTN_WEIGHT_GENERATOR_STACK_BIAS_FLAG,
        )
    return AdaptiveGeneratorStackSource(
        independent_flag=config.FF_WEIGHT_GENERATOR_STACK_INDEPENDENT_FLAG,
        hidden_dim=config.FF_WEIGHT_GENERATOR_STACK_HIDDEN_DIM,
        layer_norm_position=config.FF_WEIGHT_GENERATOR_STACK_LAYER_NORM_POSITION,
        normalization=config.FF_WEIGHT_GENERATOR_STACK_NORMALIZATION,
        num_layers=config.FF_WEIGHT_GENERATOR_STACK_NUM_LAYERS,
        activation=config.FF_WEIGHT_GENERATOR_STACK_ACTIVATION,
        residual_connection_option=(
            config.FF_WEIGHT_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
        ),
        residual_block_size=config.FF_WEIGHT_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.FF_WEIGHT_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.FF_WEIGHT_GENERATOR_STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.FF_WEIGHT_GENERATOR_STACK_DROPOUT_PROBABILITY,
        last_layer_bias_option=(
            config.FF_WEIGHT_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION
        ),
        apply_output_postprocessing_flag=(
            config.FF_WEIGHT_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
        ),
        bias_flag=config.FF_WEIGHT_GENERATOR_STACK_BIAS_FLAG,
    )


def _bias_generator_stack_source(
    config: ModuleType, role: AdaptiveRole
) -> AdaptiveGeneratorStackSource:
    if role is AdaptiveRole.MAIN:
        return AdaptiveGeneratorStackSource(
            independent_flag=config.BIAS_GENERATOR_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.BIAS_GENERATOR_STACK_HIDDEN_DIM,
            layer_norm_position=config.BIAS_GENERATOR_STACK_LAYER_NORM_POSITION,
            normalization=config.BIAS_GENERATOR_STACK_NORMALIZATION,
            num_layers=config.BIAS_GENERATOR_STACK_NUM_LAYERS,
            activation=config.BIAS_GENERATOR_STACK_ACTIVATION,
            residual_connection_option=(
                config.BIAS_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.BIAS_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.BIAS_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.BIAS_GENERATOR_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.BIAS_GENERATOR_STACK_DROPOUT_PROBABILITY,
            last_layer_bias_option=config.BIAS_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=(
                config.BIAS_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            bias_flag=config.BIAS_GENERATOR_STACK_BIAS_FLAG,
        )
    if role is AdaptiveRole.ATTENTION:
        return AdaptiveGeneratorStackSource(
            independent_flag=config.ATTN_BIAS_GENERATOR_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.ATTN_BIAS_GENERATOR_STACK_HIDDEN_DIM,
            layer_norm_position=config.ATTN_BIAS_GENERATOR_STACK_LAYER_NORM_POSITION,
            normalization=config.ATTN_BIAS_GENERATOR_STACK_NORMALIZATION,
            num_layers=config.ATTN_BIAS_GENERATOR_STACK_NUM_LAYERS,
            activation=config.ATTN_BIAS_GENERATOR_STACK_ACTIVATION,
            residual_connection_option=(
                config.ATTN_BIAS_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.ATTN_BIAS_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.ATTN_BIAS_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.ATTN_BIAS_GENERATOR_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=(config.ATTN_BIAS_GENERATOR_STACK_DROPOUT_PROBABILITY),
            last_layer_bias_option=(
                config.ATTN_BIAS_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION
            ),
            apply_output_postprocessing_flag=(
                config.ATTN_BIAS_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            bias_flag=config.ATTN_BIAS_GENERATOR_STACK_BIAS_FLAG,
        )
    return AdaptiveGeneratorStackSource(
        independent_flag=config.FF_BIAS_GENERATOR_STACK_INDEPENDENT_FLAG,
        hidden_dim=config.FF_BIAS_GENERATOR_STACK_HIDDEN_DIM,
        layer_norm_position=config.FF_BIAS_GENERATOR_STACK_LAYER_NORM_POSITION,
        normalization=config.FF_BIAS_GENERATOR_STACK_NORMALIZATION,
        num_layers=config.FF_BIAS_GENERATOR_STACK_NUM_LAYERS,
        activation=config.FF_BIAS_GENERATOR_STACK_ACTIVATION,
        residual_connection_option=(
            config.FF_BIAS_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
        ),
        residual_block_size=config.FF_BIAS_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.FF_BIAS_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.FF_BIAS_GENERATOR_STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.FF_BIAS_GENERATOR_STACK_DROPOUT_PROBABILITY,
        last_layer_bias_option=config.FF_BIAS_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION,
        apply_output_postprocessing_flag=(
            config.FF_BIAS_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
        ),
        bias_flag=config.FF_BIAS_GENERATOR_STACK_BIAS_FLAG,
    )


def _diagonal_generator_stack_source(
    config: ModuleType, role: AdaptiveRole
) -> AdaptiveGeneratorStackSource:
    if role is AdaptiveRole.MAIN:
        return AdaptiveGeneratorStackSource(
            independent_flag=config.DIAGONAL_GENERATOR_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.DIAGONAL_GENERATOR_STACK_HIDDEN_DIM,
            layer_norm_position=config.DIAGONAL_GENERATOR_STACK_LAYER_NORM_POSITION,
            normalization=config.DIAGONAL_GENERATOR_STACK_NORMALIZATION,
            num_layers=config.DIAGONAL_GENERATOR_STACK_NUM_LAYERS,
            activation=config.DIAGONAL_GENERATOR_STACK_ACTIVATION,
            residual_connection_option=(
                config.DIAGONAL_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.DIAGONAL_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.DIAGONAL_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.DIAGONAL_GENERATOR_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.DIAGONAL_GENERATOR_STACK_DROPOUT_PROBABILITY,
            last_layer_bias_option=(
                config.DIAGONAL_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION
            ),
            apply_output_postprocessing_flag=(
                config.DIAGONAL_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            bias_flag=config.DIAGONAL_GENERATOR_STACK_BIAS_FLAG,
        )
    if role is AdaptiveRole.ATTENTION:
        return AdaptiveGeneratorStackSource(
            independent_flag=config.ATTN_DIAGONAL_GENERATOR_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.ATTN_DIAGONAL_GENERATOR_STACK_HIDDEN_DIM,
            layer_norm_position=(
                config.ATTN_DIAGONAL_GENERATOR_STACK_LAYER_NORM_POSITION
            ),
            normalization=(config.ATTN_DIAGONAL_GENERATOR_STACK_NORMALIZATION),
            num_layers=config.ATTN_DIAGONAL_GENERATOR_STACK_NUM_LAYERS,
            activation=config.ATTN_DIAGONAL_GENERATOR_STACK_ACTIVATION,
            residual_connection_option=(
                config.ATTN_DIAGONAL_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.ATTN_DIAGONAL_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.ATTN_DIAGONAL_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=(
                config.ATTN_DIAGONAL_GENERATOR_STACK_RESIDUAL_MODEL_FLAG
            ),
            dropout_probability=(
                config.ATTN_DIAGONAL_GENERATOR_STACK_DROPOUT_PROBABILITY
            ),
            last_layer_bias_option=(
                config.ATTN_DIAGONAL_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION
            ),
            apply_output_postprocessing_flag=(
                config.ATTN_DIAGONAL_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            bias_flag=config.ATTN_DIAGONAL_GENERATOR_STACK_BIAS_FLAG,
        )
    return AdaptiveGeneratorStackSource(
        independent_flag=config.FF_DIAGONAL_GENERATOR_STACK_INDEPENDENT_FLAG,
        hidden_dim=config.FF_DIAGONAL_GENERATOR_STACK_HIDDEN_DIM,
        layer_norm_position=config.FF_DIAGONAL_GENERATOR_STACK_LAYER_NORM_POSITION,
        normalization=config.FF_DIAGONAL_GENERATOR_STACK_NORMALIZATION,
        num_layers=config.FF_DIAGONAL_GENERATOR_STACK_NUM_LAYERS,
        activation=config.FF_DIAGONAL_GENERATOR_STACK_ACTIVATION,
        residual_connection_option=(
            config.FF_DIAGONAL_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
        ),
        residual_block_size=config.FF_DIAGONAL_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.FF_DIAGONAL_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.FF_DIAGONAL_GENERATOR_STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.FF_DIAGONAL_GENERATOR_STACK_DROPOUT_PROBABILITY,
        last_layer_bias_option=(
            config.FF_DIAGONAL_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION
        ),
        apply_output_postprocessing_flag=(
            config.FF_DIAGONAL_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
        ),
        bias_flag=config.FF_DIAGONAL_GENERATOR_STACK_BIAS_FLAG,
    )


def _mask_generator_stack_source(
    config: ModuleType, role: AdaptiveRole
) -> AdaptiveGeneratorStackSource:
    if role is AdaptiveRole.MAIN:
        return AdaptiveGeneratorStackSource(
            independent_flag=config.MASK_GENERATOR_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.MASK_GENERATOR_STACK_HIDDEN_DIM,
            layer_norm_position=config.MASK_GENERATOR_STACK_LAYER_NORM_POSITION,
            normalization=config.MASK_GENERATOR_STACK_NORMALIZATION,
            num_layers=config.MASK_GENERATOR_STACK_NUM_LAYERS,
            activation=config.MASK_GENERATOR_STACK_ACTIVATION,
            residual_connection_option=(
                config.MASK_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.MASK_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.MASK_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.MASK_GENERATOR_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=config.MASK_GENERATOR_STACK_DROPOUT_PROBABILITY,
            last_layer_bias_option=config.MASK_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION,
            apply_output_postprocessing_flag=(
                config.MASK_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            bias_flag=config.MASK_GENERATOR_STACK_BIAS_FLAG,
        )
    if role is AdaptiveRole.ATTENTION:
        return AdaptiveGeneratorStackSource(
            independent_flag=config.ATTN_MASK_GENERATOR_STACK_INDEPENDENT_FLAG,
            hidden_dim=config.ATTN_MASK_GENERATOR_STACK_HIDDEN_DIM,
            layer_norm_position=config.ATTN_MASK_GENERATOR_STACK_LAYER_NORM_POSITION,
            normalization=config.ATTN_MASK_GENERATOR_STACK_NORMALIZATION,
            num_layers=config.ATTN_MASK_GENERATOR_STACK_NUM_LAYERS,
            activation=config.ATTN_MASK_GENERATOR_STACK_ACTIVATION,
            residual_connection_option=(
                config.ATTN_MASK_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
            ),
            residual_block_size=config.ATTN_MASK_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
            residual_rms_norm_epsilon=config.ATTN_MASK_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
            residual_model_flag=config.ATTN_MASK_GENERATOR_STACK_RESIDUAL_MODEL_FLAG,
            dropout_probability=(config.ATTN_MASK_GENERATOR_STACK_DROPOUT_PROBABILITY),
            last_layer_bias_option=(
                config.ATTN_MASK_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION
            ),
            apply_output_postprocessing_flag=(
                config.ATTN_MASK_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
            ),
            bias_flag=config.ATTN_MASK_GENERATOR_STACK_BIAS_FLAG,
        )
    return AdaptiveGeneratorStackSource(
        independent_flag=config.FF_MASK_GENERATOR_STACK_INDEPENDENT_FLAG,
        hidden_dim=config.FF_MASK_GENERATOR_STACK_HIDDEN_DIM,
        layer_norm_position=config.FF_MASK_GENERATOR_STACK_LAYER_NORM_POSITION,
        normalization=config.FF_MASK_GENERATOR_STACK_NORMALIZATION,
        num_layers=config.FF_MASK_GENERATOR_STACK_NUM_LAYERS,
        activation=config.FF_MASK_GENERATOR_STACK_ACTIVATION,
        residual_connection_option=(
            config.FF_MASK_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION
        ),
        residual_block_size=config.FF_MASK_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE,
        residual_rms_norm_epsilon=config.FF_MASK_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON,
        residual_model_flag=config.FF_MASK_GENERATOR_STACK_RESIDUAL_MODEL_FLAG,
        dropout_probability=config.FF_MASK_GENERATOR_STACK_DROPOUT_PROBABILITY,
        last_layer_bias_option=config.FF_MASK_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION,
        apply_output_postprocessing_flag=(
            config.FF_MASK_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
        ),
        bias_flag=config.FF_MASK_GENERATOR_STACK_BIAS_FLAG,
    )


def hidden_adaptive_weight_options(
    config: ModuleType,
    role: AdaptiveRole = AdaptiveRole.MAIN,
) -> HiddenAdaptiveWeightOptions:
    if role is AdaptiveRole.ATTENTION:
        return HiddenAdaptiveWeightOptions(
            generator_depth=config.ATTN_GENERATOR_DEPTH,
            option_flag=config.ATTN_WEIGHT_OPTION_FLAG,
            option=config.ATTN_WEIGHT_OPTION,
            normalization_option=config.ATTN_WEIGHT_NORMALIZATION_OPTION,
            normalization_position_option=(
                config.ATTN_WEIGHT_NORMALIZATION_POSITION_OPTION
            ),
            decay_schedule=config.ATTN_WEIGHT_DECAY_SCHEDULE,
            decay_rate=config.ATTN_WEIGHT_DECAY_RATE,
            decay_warmup_batches=config.ATTN_WEIGHT_DECAY_WARMUP_BATCHES,
            bank_expansion_factor=config.ATTN_WEIGHT_BANK_EXPANSION_FACTOR,
            generator_stack_source=adaptive_generator_stack_source(
                config, role, AdaptiveParameter.WEIGHT
            ),
        )
    if role is AdaptiveRole.FEED_FORWARD:
        return HiddenAdaptiveWeightOptions(
            generator_depth=config.FF_GENERATOR_DEPTH,
            option_flag=config.FF_WEIGHT_OPTION_FLAG,
            option=config.FF_WEIGHT_OPTION,
            normalization_option=config.FF_WEIGHT_NORMALIZATION_OPTION,
            normalization_position_option=(
                config.FF_WEIGHT_NORMALIZATION_POSITION_OPTION
            ),
            decay_schedule=config.FF_WEIGHT_DECAY_SCHEDULE,
            decay_rate=config.FF_WEIGHT_DECAY_RATE,
            decay_warmup_batches=config.FF_WEIGHT_DECAY_WARMUP_BATCHES,
            bank_expansion_factor=config.FF_WEIGHT_BANK_EXPANSION_FACTOR,
            generator_stack_source=adaptive_generator_stack_source(
                config, role, AdaptiveParameter.WEIGHT
            ),
        )
    return HiddenAdaptiveWeightOptions(
        generator_depth=config.GENERATOR_DEPTH,
        option_flag=config.WEIGHT_OPTION_FLAG,
        option=config.WEIGHT_OPTION,
        normalization_option=config.WEIGHT_NORMALIZATION_OPTION,
        normalization_position_option=(config.WEIGHT_NORMALIZATION_POSITION_OPTION),
        decay_schedule=config.WEIGHT_DECAY_SCHEDULE,
        decay_rate=config.WEIGHT_DECAY_RATE,
        decay_warmup_batches=config.WEIGHT_DECAY_WARMUP_BATCHES,
        bank_expansion_factor=config.WEIGHT_BANK_EXPANSION_FACTOR,
        generator_stack_source=adaptive_generator_stack_source(
            config, role, AdaptiveParameter.WEIGHT
        ),
    )


def hidden_adaptive_bias_options(
    config: ModuleType,
    role: AdaptiveRole = AdaptiveRole.MAIN,
) -> HiddenAdaptiveBiasOptions:
    if role is AdaptiveRole.ATTENTION:
        return HiddenAdaptiveBiasOptions(
            option_flag=config.ATTN_BIAS_OPTION_FLAG,
            option=config.ATTN_BIAS_OPTION,
            decay_schedule=config.ATTN_BIAS_DECAY_SCHEDULE,
            decay_rate=config.ATTN_BIAS_DECAY_RATE,
            decay_warmup_batches=config.ATTN_BIAS_DECAY_WARMUP_BATCHES,
            bank_expansion_factor=config.ATTN_BIAS_BANK_EXPANSION_FACTOR,
            generator_stack_source=adaptive_generator_stack_source(
                config, role, AdaptiveParameter.BIAS
            ),
        )
    if role is AdaptiveRole.FEED_FORWARD:
        return HiddenAdaptiveBiasOptions(
            option_flag=config.FF_BIAS_OPTION_FLAG,
            option=config.FF_BIAS_OPTION,
            decay_schedule=config.FF_BIAS_DECAY_SCHEDULE,
            decay_rate=config.FF_BIAS_DECAY_RATE,
            decay_warmup_batches=config.FF_BIAS_DECAY_WARMUP_BATCHES,
            bank_expansion_factor=config.FF_BIAS_BANK_EXPANSION_FACTOR,
            generator_stack_source=adaptive_generator_stack_source(
                config, role, AdaptiveParameter.BIAS
            ),
        )
    return HiddenAdaptiveBiasOptions(
        option_flag=config.BIAS_OPTION_FLAG,
        option=config.BIAS_OPTION,
        decay_schedule=config.BIAS_DECAY_SCHEDULE,
        decay_rate=config.BIAS_DECAY_RATE,
        decay_warmup_batches=config.BIAS_DECAY_WARMUP_BATCHES,
        bank_expansion_factor=config.BIAS_BANK_EXPANSION_FACTOR,
        generator_stack_source=adaptive_generator_stack_source(
            config, role, AdaptiveParameter.BIAS
        ),
    )


def hidden_adaptive_diagonal_options(
    config: ModuleType,
    role: AdaptiveRole = AdaptiveRole.MAIN,
) -> HiddenAdaptiveDiagonalOptions:
    if role is AdaptiveRole.ATTENTION:
        return HiddenAdaptiveDiagonalOptions(
            option_flag=config.ATTN_DIAGONAL_OPTION_FLAG,
            option=config.ATTN_DIAGONAL_OPTION,
            generator_stack_source=adaptive_generator_stack_source(
                config, role, AdaptiveParameter.DIAGONAL
            ),
        )
    if role is AdaptiveRole.FEED_FORWARD:
        return HiddenAdaptiveDiagonalOptions(
            option_flag=config.FF_DIAGONAL_OPTION_FLAG,
            option=config.FF_DIAGONAL_OPTION,
            generator_stack_source=adaptive_generator_stack_source(
                config, role, AdaptiveParameter.DIAGONAL
            ),
        )
    return HiddenAdaptiveDiagonalOptions(
        option_flag=config.DIAGONAL_OPTION_FLAG,
        option=config.DIAGONAL_OPTION,
        generator_stack_source=adaptive_generator_stack_source(
            config, role, AdaptiveParameter.DIAGONAL
        ),
    )


def hidden_adaptive_mask_options(
    config: ModuleType,
    role: AdaptiveRole = AdaptiveRole.MAIN,
) -> HiddenAdaptiveMaskOptions:
    if role is AdaptiveRole.ATTENTION:
        return HiddenAdaptiveMaskOptions(
            option_flag=config.ATTN_MASK_OPTION_FLAG,
            row_mask_option=config.ATTN_ROW_MASK_OPTION,
            mask_dimension_option=config.ATTN_MASK_DIMENSION_OPTION,
            mask_threshold=config.ATTN_MASK_THRESHOLD,
            mask_surrogate_scale=config.ATTN_MASK_SURROGATE_SCALE,
            mask_floor=config.ATTN_MASK_FLOOR,
            mask_transition_width=config.ATTN_MASK_TRANSITION_WIDTH,
            generator_stack_source=adaptive_generator_stack_source(
                config, role, AdaptiveParameter.MASK
            ),
        )
    if role is AdaptiveRole.FEED_FORWARD:
        return HiddenAdaptiveMaskOptions(
            option_flag=config.FF_MASK_OPTION_FLAG,
            row_mask_option=config.FF_ROW_MASK_OPTION,
            mask_dimension_option=config.FF_MASK_DIMENSION_OPTION,
            mask_threshold=config.FF_MASK_THRESHOLD,
            mask_surrogate_scale=config.FF_MASK_SURROGATE_SCALE,
            mask_floor=config.FF_MASK_FLOOR,
            mask_transition_width=config.FF_MASK_TRANSITION_WIDTH,
            generator_stack_source=adaptive_generator_stack_source(
                config, role, AdaptiveParameter.MASK
            ),
        )
    return HiddenAdaptiveMaskOptions(
        option_flag=config.MASK_OPTION_FLAG,
        row_mask_option=config.ROW_MASK_OPTION,
        mask_dimension_option=config.MASK_DIMENSION_OPTION,
        mask_threshold=config.MASK_THRESHOLD,
        mask_surrogate_scale=config.MASK_SURROGATE_SCALE,
        mask_floor=config.MASK_FLOOR,
        mask_transition_width=config.MASK_TRANSITION_WIDTH,
        generator_stack_source=adaptive_generator_stack_source(
            config, role, AdaptiveParameter.MASK
        ),
    )
