from emperor.augmentations.adaptive_parameters import (
    AdaptiveParameterGroupingScopeOptions,
    AdaptiveParameterInputOrderOptions,
    AdditiveDynamicBiasConfig,  # noqa: F401
    AffineTransformDynamicBiasConfig,  # noqa: F401
    AntiDynamicDiagonalConfig,  # noqa: F401
    AttentionGroupingConfig,  # noqa: F401
    AxisMaskConfig,
    BankExpansionFactorOptions,
    CombinedDynamicDiagonalConfig,  # noqa: F401
    DiagonalAxisMaskConfig,  # noqa: F401
    DiagonallyModulatedLowRankDynamicWeightConfig,  # noqa: F401
    DualModelDynamicWeightConfig,  # noqa: F401
    DynamicBiasConfig,
    DynamicDiagonalConfig,
    DynamicWeightConfig,
    GeneratorDynamicBiasConfig,  # noqa: F401
    GroupingConfig,
    HypernetworkDynamicWeightConfig,  # noqa: F401
    LayeredWeightedBankDynamicWeightConfig,  # noqa: F401
    LowRankDynamicWeightConfig,  # noqa: F401
    LowRankFactorSourceOptions,
    MaskDimensionOptions,
    MatrixBiasMixtureConfig,  # noqa: F401
    MatrixWeightsMixtureConfig,  # noqa: F401
    MeanGroupingConfig,  # noqa: F401
    MeanStdGroupingConfig,  # noqa: F401
    MultiplicativeDynamicBiasConfig,  # noqa: F401
    OuterProductMaskConfig,  # noqa: F401
    PerAxisScoreMaskConfig,  # noqa: F401
    RMSGroupingConfig,  # noqa: F401
    SigmoidGatedDynamicBiasConfig,  # noqa: F401
    SingleModelDynamicWeightConfig,  # noqa: F401
    SoftWeightedBankDynamicWeightConfig,  # noqa: F401
    StandardDynamicDiagonalConfig,
    SumGroupingConfig,  # noqa: F401
    SummaryNormalizationOptions,
    TanhGatedDynamicBiasConfig,  # noqa: F401
    TopSliceAxisMaskConfig,  # noqa: F401
    WeightDecayScheduleOptions,
    WeightedBankDynamicBiasConfig,  # noqa: F401
    WeightInformedScoreAxisMaskConfig,  # noqa: F401
    WeightNormalizationOptions,
    WeightNormalizationPositionOptions,
)
from emperor.config import ConfigBase
from emperor.experts import (
    DroppedTokenOptions,
    ExpertWeightingPositionOptions,
    RoutingInitializationMode,
)
from emperor.halting import (
    HaltingConfig,
    HaltingHiddenStateModeOptions,
    StickBreakingConfig,
)
from emperor.layers import (
    ActivationOptions,
    AdditiveResidualConfig,
    AttentionResidualConfig,  # noqa: F401
    LastLayerBiasOptions,
    LayerGateOptions,
    LayerNormPositionOptions,
    NormalizationOptions,
    ResidualConfig,
    WeightedBlendResidualConfig,  # noqa: F401
    WeightedResidualConfig,  # noqa: F401
)
from emperor.memory import (
    AttentionDynamicMemoryConfig,  # noqa: F401
    DynamicMemoryConfig,
    ElementWiseWeightedDynamicMemoryConfig,  # noqa: F401
    GatedResidualDynamicMemoryConfig,
    MemoryPositionOptions,
    WeightedDynamicMemoryConfig,  # noqa: F401
)
from model_runtime.packages.runtime_values import positive_runtime_fields

#########################################################################
# Global
BATCH_SIZE: int = 64
INPUT_DIM: int = 224 * 224 * 3
HIDDEN_DIM: int = 32
RUNTIME_VALUE_CONSTRAINTS = positive_runtime_fields("HIDDEN_DIM")
OUTPUT_DIM: int = 10
LEARNING_RATE: float = 1e-3
NUM_EPOCHS: int = 10

#########################################################################
# Trainer
TRAINER_ACCELERATOR: str = "cpu"
TRAINER_DEVICES: int = 1
TRAINER_GRADIENT_CLIP_VAL: float = 1.0
TRAINER_GRADIENT_CLIP_ALGORITHM: str = "norm"
TRAINER_ACCUMULATE_GRAD_BATCHES: int = 1
TRAINER_PRECISION: str = "32-true"
TRAINER_DETERMINISTIC: bool = False
TRAINER_BENCHMARK: bool = True
TRAINER_MAX_STEPS: int = -1
TRAINER_MAX_TIME: str | None = None
TRAINER_VAL_CHECK_INTERVAL: float = 1.0
TRAINER_LIMIT_TRAIN_BATCHES: float = 1.0
TRAINER_LIMIT_VAL_BATCHES: float = 1.0
TRAINER_OVERFIT_BATCHES: int | float = 0.0
TRAINER_NUM_SANITY_VAL_STEPS: int = 2
TRAINER_LOG_EVERY_N_STEPS: int = 50
TRAINER_ENABLE_PROGRESS_BAR: bool = False
TRAINER_ENABLE_CHECKPOINTING: bool = False
TRAINER_ENABLE_MODEL_SUMMARY: bool = False
TRAINER_PROFILER: str | None = None
MONITOR_LOG_EVERY_N_STEPS: int = 100

# Run
DATA_NUM_WORKERS: int = 4
RUN_TEST_AFTER_FIT: bool = True
SEED: int | None = None

# Callback
CALLBACK_EARLY_STOPPING_PATIENCE: int = 0
CALLBACK_EARLY_STOPPING_METRIC: str = "validation/accuracy"
CALLBACK_EARLY_STOPPING_MIN_DELTA: float = 0.0
CALLBACK_EARLY_STOPPING_STRICT: bool = True
CALLBACK_EARLY_STOPPING_CHECK_FINITE: bool = True
CALLBACK_CHECKPOINT_FLAG: bool = False

#########################################################################
# Layer Stack Options
# - hidden_dim comes from the global HIDDEN_DIM field above.
# - Token and channel mixer stacks inherit applicable activation/bias defaults.
LAYER_NORM_POSITION: LayerNormPositionOptions = LayerNormPositionOptions.BEFORE
NORMALIZATION: NormalizationOptions = NormalizationOptions.RMS_NORM
ENCODER_OUTPUT_NORMALIZATION: NormalizationOptions = NormalizationOptions.LAYER_NORM
STACK_NUM_LAYERS: int = 8
STACK_ACTIVATION: ActivationOptions = ActivationOptions.GELU
STACK_DROPOUT_PROBABILITY: float = 0.0
STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions = LastLayerBiasOptions.DEFAULT
STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool = True
STACK_BIAS_FLAG: bool = True

## Mixer Block Options
MIXER_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] = AdditiveResidualConfig
MIXER_RESIDUAL_MODEL_FLAG: bool = False
MIXER_RESIDUAL_BLOCK_SIZE: int | None = None
MIXER_RESIDUAL_RMS_NORM_EPSILON: float | None = None

#########################################################################
# Layer Stack Submodule Options
SUBMODULE_STACK_HIDDEN_DIM: int = HIDDEN_DIM
SUBMODULE_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions = (
    LayerNormPositionOptions.DISABLED
)
SUBMODULE_STACK_NORMALIZATION: NormalizationOptions = NormalizationOptions.RMS_NORM
SUBMODULE_STACK_NUM_LAYERS: int = 1
SUBMODULE_STACK_ACTIVATION: ActivationOptions = ActivationOptions.GELU
SUBMODULE_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
SUBMODULE_STACK_RESIDUAL_MODEL_FLAG: bool = False
SUBMODULE_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
SUBMODULE_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
SUBMODULE_STACK_DROPOUT_PROBABILITY: float = 0.0
SUBMODULE_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions = (
    LastLayerBiasOptions.DEFAULT
)
SUBMODULE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool = False
SUBMODULE_STACK_BIAS_FLAG: bool = STACK_BIAS_FLAG

#########################################################################
# Residual Options
# - False uses the residual variant's learned query or coefficient parameters.
# - True uses the residual stack for input-dependent queries or coefficients.
# - For every attention residual selector, supply its RESIDUAL_BLOCK_SIZE and
#   RESIDUAL_RMS_NORM_EPSILON explicitly (suggested: 1 for full attention, 1e-6).
STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
STACK_RESIDUAL_MODEL_FLAG: bool = False
STACK_RESIDUAL_BLOCK_SIZE: int | None = None
STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
## Residual Stack Options
# - If False, residual stack options inherit layer stack submodule options.
RESIDUAL_STACK_INDEPENDENT_FLAG: bool = False
RESIDUAL_STACK_HIDDEN_DIM: int | None = None
RESIDUAL_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
RESIDUAL_STACK_NORMALIZATION: NormalizationOptions | None = None
RESIDUAL_STACK_NUM_LAYERS: int | None = None
RESIDUAL_STACK_ACTIVATION: ActivationOptions | None = None
RESIDUAL_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
RESIDUAL_STACK_RESIDUAL_MODEL_FLAG: bool = False
RESIDUAL_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
RESIDUAL_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
RESIDUAL_STACK_DROPOUT_PROBABILITY: float | None = None
RESIDUAL_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
RESIDUAL_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
RESIDUAL_STACK_BIAS_FLAG: bool | None = None


#########################################################################
# Gate Options
# - If `STACK_GATE_FLAG` is False, the gate-specific parameters below are ignored.
STACK_GATE_FLAG: bool = False
GATE_OPTION: LayerGateOptions | None = LayerGateOptions.MULTIPLIER
GATE_ACTIVATION: ActivationOptions | None = ActivationOptions.SIGMOID
## Gate Stack Options
# - If False, gate model stack options inherit the layer stack submodule options.
GATE_STACK_INDEPENDENT_FLAG: bool = False
GATE_STACK_HIDDEN_DIM: int | None = None
GATE_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
GATE_STACK_NORMALIZATION: NormalizationOptions | None = None
GATE_STACK_NUM_LAYERS: int | None = None
GATE_STACK_ACTIVATION: ActivationOptions | None = ActivationOptions.TANH
GATE_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
GATE_STACK_RESIDUAL_MODEL_FLAG: bool = False
GATE_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
GATE_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
GATE_STACK_DROPOUT_PROBABILITY: float | None = None
GATE_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = True
GATE_STACK_BIAS_FLAG: bool | None = True

#########################################################################
# Halting Options
# - If `STACK_HALTING_FLAG` is False, the halting-specific parameters below are ignored.
STACK_HALTING_FLAG: bool = False
HALTING_OPTION: type[HaltingConfig] = StickBreakingConfig
HALTING_THRESHOLD: float = 0.999
HALTING_DROPOUT: float = 0.0
HALTING_HIDDEN_STATE_MODE: HaltingHiddenStateModeOptions = (
    HaltingHiddenStateModeOptions.RAW
)
## Halting Stack Options
# - If False, halting model stack options inherit the layer stack submodule options.
HALTING_STACK_INDEPENDENT_FLAG: bool = False
HALTING_STACK_HIDDEN_DIM: int | None = None
HALTING_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = (
    LayerNormPositionOptions.DISABLED
)
HALTING_STACK_NORMALIZATION: NormalizationOptions | None = None
HALTING_STACK_NUM_LAYERS: int | None = None
HALTING_STACK_ACTIVATION: ActivationOptions | None = None
HALTING_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
HALTING_STACK_RESIDUAL_MODEL_FLAG: bool = False
HALTING_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
HALTING_STACK_DROPOUT_PROBABILITY: float | None = None
HALTING_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = (
    LastLayerBiasOptions.DISABLED
)
HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
HALTING_STACK_BIAS_FLAG: bool | None = None

#########################################################################
# Memory Options
# - If `MEMORY_FLAG` is False, the memory-specific parameters below are ignored.
MEMORY_FLAG: bool = False
MEMORY_OPTION: type[DynamicMemoryConfig] = GatedResidualDynamicMemoryConfig
MEMORY_POSITION_OPTION: MemoryPositionOptions = MemoryPositionOptions.AFTER_AFFINE
MEMORY_TEST_TIME_TRAINING_LEARNING_RATE: float | None = None
MEMORY_TEST_TIME_TRAINING_NUM_INNER_STEPS: int | None = None
## Memory Stack Options
# - If False, memory model stack options inherit the layer stack submodule options.
MEMORY_STACK_INDEPENDENT_FLAG: bool = False
MEMORY_STACK_HIDDEN_DIM: int | None = None
MEMORY_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
MEMORY_STACK_NORMALIZATION: NormalizationOptions | None = None
MEMORY_STACK_NUM_LAYERS: int | None = None
MEMORY_STACK_ACTIVATION: ActivationOptions | None = None
MEMORY_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
MEMORY_STACK_RESIDUAL_MODEL_FLAG: bool = False
MEMORY_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
MEMORY_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
MEMORY_STACK_DROPOUT_PROBABILITY: float | None = None
MEMORY_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
MEMORY_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
MEMORY_STACK_BIAS_FLAG: bool | None = None

#########################################################################
# Recurrent Layer Options
# - If `RECURRENT_FLAG` is False, the recurrent-specific parameters below are ignored.
RECURRENT_FLAG: bool = False
RECURRENT_MAX_STEPS: int = 2
RECURRENT_INITIAL_ITERATIONS: int = 2
RECURRENT_GRADIENT_TRANSITION_COUNT: int | None = None
RECURRENT_NO_GRADIENT_TRANSITION_COUNT: int | None = None
RECURRENT_ITERATION_INCREMENT: int = 1
RECURRENT_FORWARD_CALLS_BEFORE_ITERATION_INCREMENT: int = 1
RECURRENT_SMOOTH_ITERATION_GROWTH_FLAG: bool = False
RECURRENT_LAYER_NORM_POSITION: LayerNormPositionOptions = (
    LayerNormPositionOptions.DISABLED
)
RECURRENT_NORMALIZATION: NormalizationOptions = NormalizationOptions.LAYER_NORM
RECURRENT_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
RECURRENT_RESIDUAL_MODEL_FLAG: bool = False
RECURRENT_RESIDUAL_BLOCK_SIZE: int | None = None
RECURRENT_RESIDUAL_RMS_NORM_EPSILON: float | None = None
## Recurrent Gate Options
RECURRENT_STACK_GATE_FLAG: bool = False
RECURRENT_GATE_OPTION: LayerGateOptions | None = LayerGateOptions.MULTIPLIER
RECURRENT_GATE_ACTIVATION: ActivationOptions | None = ActivationOptions.SIGMOID
### Recurrent Gate Stack Options
# - If False, recurrent gate stack options inherit gate/submodule stack options.
RECURRENT_GATE_STACK_INDEPENDENT_FLAG: bool = False
RECURRENT_GATE_STACK_HIDDEN_DIM: int | None = None
RECURRENT_GATE_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
RECURRENT_GATE_STACK_NORMALIZATION: NormalizationOptions | None = None
RECURRENT_GATE_STACK_NUM_LAYERS: int | None = None
RECURRENT_GATE_STACK_ACTIVATION: ActivationOptions | None = None
RECURRENT_GATE_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
RECURRENT_GATE_STACK_RESIDUAL_MODEL_FLAG: bool = False
RECURRENT_GATE_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
RECURRENT_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
RECURRENT_GATE_STACK_DROPOUT_PROBABILITY: float | None = None
RECURRENT_GATE_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
RECURRENT_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
RECURRENT_GATE_STACK_BIAS_FLAG: bool | None = None
## Recurrent Halting Options
RECURRENT_STACK_HALTING_FLAG: bool = False
RECURRENT_HALTING_OPTION: type[HaltingConfig] = StickBreakingConfig
RECURRENT_HALTING_THRESHOLD: float = 0.999
RECURRENT_HALTING_DROPOUT: float = 0.0
RECURRENT_HALTING_HIDDEN_STATE_MODE: HaltingHiddenStateModeOptions = (
    HaltingHiddenStateModeOptions.RAW
)
### Recurrent Halting Stack Options
# - If False, recurrent halting stack options inherit halting/submodule stack options.
RECURRENT_HALTING_STACK_INDEPENDENT_FLAG: bool = False
RECURRENT_HALTING_STACK_HIDDEN_DIM: int | None = None
RECURRENT_HALTING_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
RECURRENT_HALTING_STACK_NORMALIZATION: NormalizationOptions | None = None
RECURRENT_HALTING_STACK_NUM_LAYERS: int | None = None
RECURRENT_HALTING_STACK_ACTIVATION: ActivationOptions | None = None
RECURRENT_HALTING_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
RECURRENT_HALTING_STACK_RESIDUAL_MODEL_FLAG: bool = False
RECURRENT_HALTING_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
RECURRENT_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
RECURRENT_HALTING_STACK_DROPOUT_PROBABILITY: float | None = None
RECURRENT_HALTING_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
RECURRENT_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
RECURRENT_HALTING_STACK_BIAS_FLAG: bool | None = None
## Recurrent Memory Options
RECURRENT_MEMORY_FLAG: bool = False

#########################################################################
# MLP Mixer Options
## Controller Stack Compatibility Options
# - These aliases mirror the canonical layer stack submodule options.
CONTROLLER_STACK_HIDDEN_DIM: int = SUBMODULE_STACK_HIDDEN_DIM
CONTROLLER_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions = (
    SUBMODULE_STACK_LAYER_NORM_POSITION
)
CONTROLLER_STACK_NORMALIZATION: NormalizationOptions = SUBMODULE_STACK_NORMALIZATION
CONTROLLER_STACK_NUM_LAYERS: int = SUBMODULE_STACK_NUM_LAYERS
CONTROLLER_STACK_ACTIVATION: ActivationOptions = SUBMODULE_STACK_ACTIVATION
CONTROLLER_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = (
    SUBMODULE_STACK_RESIDUAL_CONNECTION_OPTION
)
CONTROLLER_STACK_RESIDUAL_MODEL_FLAG: bool = False
CONTROLLER_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
CONTROLLER_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
CONTROLLER_STACK_DROPOUT_PROBABILITY: float = SUBMODULE_STACK_DROPOUT_PROBABILITY
CONTROLLER_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions = (
    SUBMODULE_STACK_LAST_LAYER_BIAS_OPTION
)
CONTROLLER_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool = (
    SUBMODULE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG
)
CONTROLLER_STACK_BIAS_FLAG: bool = SUBMODULE_STACK_BIAS_FLAG

## Output Layer Options
OUTPUT_BIAS_FLAG: bool = True

## Image Patch Options
IMAGE_PATCH_SIZE: int = 16
INPUT_CHANNELS: int = 3
IMAGE_HEIGHT: int = 224
PATCH_DROPOUT_PROBABILITY: float = 0.0
PATCH_BIAS_FLAG: bool = True

## Token Mixer Stack Options
# - STACK_ACTIVATION and STACK_BIAS_FLAG supply inherited branch defaults.
# Temporary memory tokens mixed alongside the original token positions.
TOKEN_MIXER_SOURCE_MEMORY_FLAG: bool = False
TOKEN_MIXER_SOURCE_MEMORY_OPTION: type[DynamicMemoryConfig] = (
    GatedResidualDynamicMemoryConfig
)
TOKEN_MIXER_SOURCE_MEMORY_NUM_MEMORY_SLOTS: int = 4
TOKEN_MIXER_SOURCE_MEMORY_TEST_TIME_TRAINING_LEARNING_RATE: float | None = None
TOKEN_MIXER_SOURCE_MEMORY_TEST_TIME_TRAINING_NUM_INNER_STEPS: int | None = None

TOKEN_MIXER_STACK_HIDDEN_DIM: int = 64
TOKEN_MIXER_NUM_LAYERS: int = 2
TOKEN_MIXER_STACK_ACTIVATION: ActivationOptions = STACK_ACTIVATION
TOKEN_MIXER_STACK_DROPOUT_PROBABILITY: float = 0.0
TOKEN_MIXER_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions = (
    LayerNormPositionOptions.DISABLED
)
TOKEN_MIXER_STACK_NORMALIZATION: NormalizationOptions = NormalizationOptions.RMS_NORM
TOKEN_MIXER_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
TOKEN_MIXER_STACK_RESIDUAL_MODEL_FLAG: bool = False
TOKEN_MIXER_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
TOKEN_MIXER_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
TOKEN_MIXER_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions = (
    LastLayerBiasOptions.DEFAULT
)
TOKEN_MIXER_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool = False

## Channel Mixer Stack Options
# - STACK_ACTIVATION and STACK_BIAS_FLAG supply inherited branch defaults.
CHANNEL_MIXER_STACK_HIDDEN_DIM: int = 128
CHANNEL_MIXER_NUM_LAYERS: int = 2
CHANNEL_MIXER_STACK_ACTIVATION: ActivationOptions = STACK_ACTIVATION
CHANNEL_MIXER_STACK_DROPOUT_PROBABILITY: float = 0.0
CHANNEL_MIXER_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions = (
    LayerNormPositionOptions.DISABLED
)
CHANNEL_MIXER_STACK_NORMALIZATION: NormalizationOptions = NormalizationOptions.RMS_NORM
CHANNEL_MIXER_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
CHANNEL_MIXER_STACK_RESIDUAL_MODEL_FLAG: bool = False
CHANNEL_MIXER_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
CHANNEL_MIXER_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
CHANNEL_MIXER_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions = (
    LastLayerBiasOptions.DEFAULT
)
CHANNEL_MIXER_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool = False

#########################################################################
# Token Mixer Gate Options
# - If `TOKEN_MIXER_STACK_GATE_FLAG` is False, the gate-specific parameters below are ignored.
TOKEN_MIXER_STACK_GATE_FLAG: bool = False
TOKEN_MIXER_GATE_OPTION: LayerGateOptions | None = LayerGateOptions.MULTIPLIER
TOKEN_MIXER_GATE_ACTIVATION: ActivationOptions | None = ActivationOptions.SIGMOID
## Token Mixer Gate Stack Options
# - If False, gate stack options inherit the token mixer stack options.
TOKEN_MIXER_GATE_STACK_INDEPENDENT_FLAG: bool = False
TOKEN_MIXER_GATE_STACK_HIDDEN_DIM: int | None = None
TOKEN_MIXER_GATE_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
TOKEN_MIXER_GATE_STACK_NORMALIZATION: NormalizationOptions | None = None
TOKEN_MIXER_GATE_STACK_NUM_LAYERS: int | None = None
TOKEN_MIXER_GATE_STACK_ACTIVATION: ActivationOptions | None = ActivationOptions.TANH
TOKEN_MIXER_GATE_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
TOKEN_MIXER_GATE_STACK_RESIDUAL_MODEL_FLAG: bool = False
TOKEN_MIXER_GATE_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
TOKEN_MIXER_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
TOKEN_MIXER_GATE_STACK_DROPOUT_PROBABILITY: float | None = None
TOKEN_MIXER_GATE_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
TOKEN_MIXER_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = True
TOKEN_MIXER_GATE_STACK_BIAS_FLAG: bool | None = True

#########################################################################
# Token Mixer Halting Options
# - If `TOKEN_MIXER_STACK_HALTING_FLAG` is False, the halting-specific parameters below are ignored.
TOKEN_MIXER_STACK_HALTING_FLAG: bool = False
TOKEN_MIXER_HALTING_OPTION: type[HaltingConfig] = StickBreakingConfig
TOKEN_MIXER_HALTING_THRESHOLD: float = 0.999
TOKEN_MIXER_HALTING_DROPOUT: float = 0.0
TOKEN_MIXER_HALTING_HIDDEN_STATE_MODE: HaltingHiddenStateModeOptions = (
    HaltingHiddenStateModeOptions.RAW
)
## Token Mixer Halting Stack Options
# - If False, halting stack options inherit the token mixer stack options.
TOKEN_MIXER_HALTING_STACK_INDEPENDENT_FLAG: bool = False
TOKEN_MIXER_HALTING_STACK_HIDDEN_DIM: int | None = None
TOKEN_MIXER_HALTING_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = (
    LayerNormPositionOptions.DISABLED
)
TOKEN_MIXER_HALTING_STACK_NORMALIZATION: NormalizationOptions | None = None
TOKEN_MIXER_HALTING_STACK_NUM_LAYERS: int | None = None
TOKEN_MIXER_HALTING_STACK_ACTIVATION: ActivationOptions | None = None
TOKEN_MIXER_HALTING_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
TOKEN_MIXER_HALTING_STACK_RESIDUAL_MODEL_FLAG: bool = False
TOKEN_MIXER_HALTING_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
TOKEN_MIXER_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
TOKEN_MIXER_HALTING_STACK_DROPOUT_PROBABILITY: float | None = None
TOKEN_MIXER_HALTING_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = (
    LastLayerBiasOptions.DISABLED
)
TOKEN_MIXER_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
TOKEN_MIXER_HALTING_STACK_BIAS_FLAG: bool | None = None

#########################################################################
# Token Mixer Memory Options
# - If `TOKEN_MIXER_MEMORY_FLAG` is False, the memory-specific parameters below are ignored.
TOKEN_MIXER_MEMORY_FLAG: bool = False
TOKEN_MIXER_MEMORY_OPTION: type[DynamicMemoryConfig] = GatedResidualDynamicMemoryConfig
TOKEN_MIXER_MEMORY_POSITION_OPTION: MemoryPositionOptions = (
    MemoryPositionOptions.AFTER_AFFINE
)
TOKEN_MIXER_MEMORY_TEST_TIME_TRAINING_LEARNING_RATE: float | None = None
TOKEN_MIXER_MEMORY_TEST_TIME_TRAINING_NUM_INNER_STEPS: int | None = None
## Token Mixer Memory Stack Options
# - If False, memory stack options inherit the token mixer stack options.
TOKEN_MIXER_MEMORY_STACK_INDEPENDENT_FLAG: bool = False
TOKEN_MIXER_MEMORY_STACK_HIDDEN_DIM: int | None = None
TOKEN_MIXER_MEMORY_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
TOKEN_MIXER_MEMORY_STACK_NORMALIZATION: NormalizationOptions | None = None
TOKEN_MIXER_MEMORY_STACK_NUM_LAYERS: int | None = None
TOKEN_MIXER_MEMORY_STACK_ACTIVATION: ActivationOptions | None = None
TOKEN_MIXER_MEMORY_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
TOKEN_MIXER_MEMORY_STACK_RESIDUAL_MODEL_FLAG: bool = False
TOKEN_MIXER_MEMORY_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
TOKEN_MIXER_MEMORY_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
TOKEN_MIXER_MEMORY_STACK_DROPOUT_PROBABILITY: float | None = None
TOKEN_MIXER_MEMORY_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
TOKEN_MIXER_MEMORY_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
TOKEN_MIXER_MEMORY_STACK_BIAS_FLAG: bool | None = None

#########################################################################
# Token Mixer Recurrent Layer Options
# - If `TOKEN_MIXER_RECURRENT_FLAG` is False, the recurrent-specific parameters below are ignored.
TOKEN_MIXER_RECURRENT_FLAG: bool = False
TOKEN_MIXER_RECURRENT_MAX_STEPS: int = 2
TOKEN_MIXER_RECURRENT_LAYER_NORM_POSITION: LayerNormPositionOptions = (
    LayerNormPositionOptions.DISABLED
)
TOKEN_MIXER_RECURRENT_NORMALIZATION: NormalizationOptions = (
    NormalizationOptions.LAYER_NORM
)
TOKEN_MIXER_RECURRENT_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
TOKEN_MIXER_RECURRENT_RESIDUAL_MODEL_FLAG: bool = False
TOKEN_MIXER_RECURRENT_RESIDUAL_BLOCK_SIZE: int | None = None
TOKEN_MIXER_RECURRENT_RESIDUAL_RMS_NORM_EPSILON: float | None = None
## Token Mixer Recurrent Gate Options
TOKEN_MIXER_RECURRENT_STACK_GATE_FLAG: bool = False
TOKEN_MIXER_RECURRENT_GATE_OPTION: LayerGateOptions | None = LayerGateOptions.MULTIPLIER
TOKEN_MIXER_RECURRENT_GATE_ACTIVATION: ActivationOptions | None = (
    ActivationOptions.SIGMOID
)
### Token Mixer Recurrent Gate Stack Options
# - If False, recurrent gate stack options inherit the token mixer stack options.
TOKEN_MIXER_RECURRENT_GATE_STACK_INDEPENDENT_FLAG: bool = False
TOKEN_MIXER_RECURRENT_GATE_STACK_HIDDEN_DIM: int | None = None
TOKEN_MIXER_RECURRENT_GATE_STACK_LAYER_NORM_POSITION: (
    LayerNormPositionOptions | None
) = None
TOKEN_MIXER_RECURRENT_GATE_STACK_NORMALIZATION: NormalizationOptions | None = None
TOKEN_MIXER_RECURRENT_GATE_STACK_NUM_LAYERS: int | None = None
TOKEN_MIXER_RECURRENT_GATE_STACK_ACTIVATION: ActivationOptions | None = None
TOKEN_MIXER_RECURRENT_GATE_STACK_RESIDUAL_CONNECTION_OPTION: (
    type[ResidualConfig] | None
) = None
TOKEN_MIXER_RECURRENT_GATE_STACK_RESIDUAL_MODEL_FLAG: bool = False
TOKEN_MIXER_RECURRENT_GATE_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
TOKEN_MIXER_RECURRENT_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
TOKEN_MIXER_RECURRENT_GATE_STACK_DROPOUT_PROBABILITY: float | None = None
TOKEN_MIXER_RECURRENT_GATE_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = (
    None
)
TOKEN_MIXER_RECURRENT_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
TOKEN_MIXER_RECURRENT_GATE_STACK_BIAS_FLAG: bool | None = None
## Token Mixer Recurrent Halting Options
TOKEN_MIXER_RECURRENT_STACK_HALTING_FLAG: bool = False
TOKEN_MIXER_RECURRENT_HALTING_OPTION: type[HaltingConfig] = StickBreakingConfig
TOKEN_MIXER_RECURRENT_HALTING_THRESHOLD: float = 0.999
TOKEN_MIXER_RECURRENT_HALTING_DROPOUT: float = 0.0
TOKEN_MIXER_RECURRENT_HALTING_HIDDEN_STATE_MODE: HaltingHiddenStateModeOptions = (
    HaltingHiddenStateModeOptions.RAW
)
### Token Mixer Recurrent Halting Stack Options
# - If False, recurrent halting stack options inherit the token mixer stack options.
TOKEN_MIXER_RECURRENT_HALTING_STACK_INDEPENDENT_FLAG: bool = False
TOKEN_MIXER_RECURRENT_HALTING_STACK_HIDDEN_DIM: int | None = None
TOKEN_MIXER_RECURRENT_HALTING_STACK_LAYER_NORM_POSITION: (
    LayerNormPositionOptions | None
) = None
TOKEN_MIXER_RECURRENT_HALTING_STACK_NORMALIZATION: NormalizationOptions | None = None
TOKEN_MIXER_RECURRENT_HALTING_STACK_NUM_LAYERS: int | None = None
TOKEN_MIXER_RECURRENT_HALTING_STACK_ACTIVATION: ActivationOptions | None = None
TOKEN_MIXER_RECURRENT_HALTING_STACK_RESIDUAL_CONNECTION_OPTION: (
    type[ResidualConfig] | None
) = None
TOKEN_MIXER_RECURRENT_HALTING_STACK_RESIDUAL_MODEL_FLAG: bool = False
TOKEN_MIXER_RECURRENT_HALTING_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
TOKEN_MIXER_RECURRENT_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
TOKEN_MIXER_RECURRENT_HALTING_STACK_DROPOUT_PROBABILITY: float | None = None
TOKEN_MIXER_RECURRENT_HALTING_STACK_LAST_LAYER_BIAS_OPTION: (
    LastLayerBiasOptions | None
) = None
TOKEN_MIXER_RECURRENT_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
TOKEN_MIXER_RECURRENT_HALTING_STACK_BIAS_FLAG: bool | None = None

#########################################################################
# Channel Mixer Gate Options
# - If `CHANNEL_MIXER_STACK_GATE_FLAG` is False, the gate-specific parameters below are ignored.
CHANNEL_MIXER_STACK_GATE_FLAG: bool = False
CHANNEL_MIXER_GATE_OPTION: LayerGateOptions | None = LayerGateOptions.MULTIPLIER
CHANNEL_MIXER_GATE_ACTIVATION: ActivationOptions | None = ActivationOptions.SIGMOID
## Channel Mixer Gate Stack Options
# - If False, gate stack options inherit the channel mixer stack options.
CHANNEL_MIXER_GATE_STACK_INDEPENDENT_FLAG: bool = False
CHANNEL_MIXER_GATE_STACK_HIDDEN_DIM: int | None = None
CHANNEL_MIXER_GATE_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
CHANNEL_MIXER_GATE_STACK_NORMALIZATION: NormalizationOptions | None = None
CHANNEL_MIXER_GATE_STACK_NUM_LAYERS: int | None = None
CHANNEL_MIXER_GATE_STACK_ACTIVATION: ActivationOptions | None = ActivationOptions.TANH
CHANNEL_MIXER_GATE_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
CHANNEL_MIXER_GATE_STACK_RESIDUAL_MODEL_FLAG: bool = False
CHANNEL_MIXER_GATE_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
CHANNEL_MIXER_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
CHANNEL_MIXER_GATE_STACK_DROPOUT_PROBABILITY: float | None = None
CHANNEL_MIXER_GATE_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
CHANNEL_MIXER_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = True
CHANNEL_MIXER_GATE_STACK_BIAS_FLAG: bool | None = True

#########################################################################
# Channel Mixer Halting Options
# - If `CHANNEL_MIXER_STACK_HALTING_FLAG` is False, the halting-specific parameters below are ignored.
CHANNEL_MIXER_STACK_HALTING_FLAG: bool = False
CHANNEL_MIXER_HALTING_OPTION: type[HaltingConfig] = StickBreakingConfig
CHANNEL_MIXER_HALTING_THRESHOLD: float = 0.999
CHANNEL_MIXER_HALTING_DROPOUT: float = 0.0
CHANNEL_MIXER_HALTING_HIDDEN_STATE_MODE: HaltingHiddenStateModeOptions = (
    HaltingHiddenStateModeOptions.RAW
)
## Channel Mixer Halting Stack Options
# - If False, halting stack options inherit the channel mixer stack options.
CHANNEL_MIXER_HALTING_STACK_INDEPENDENT_FLAG: bool = False
CHANNEL_MIXER_HALTING_STACK_HIDDEN_DIM: int | None = None
CHANNEL_MIXER_HALTING_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = (
    LayerNormPositionOptions.DISABLED
)
CHANNEL_MIXER_HALTING_STACK_NORMALIZATION: NormalizationOptions | None = None
CHANNEL_MIXER_HALTING_STACK_NUM_LAYERS: int | None = None
CHANNEL_MIXER_HALTING_STACK_ACTIVATION: ActivationOptions | None = None
CHANNEL_MIXER_HALTING_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = (
    None
)
CHANNEL_MIXER_HALTING_STACK_RESIDUAL_MODEL_FLAG: bool = False
CHANNEL_MIXER_HALTING_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
CHANNEL_MIXER_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
CHANNEL_MIXER_HALTING_STACK_DROPOUT_PROBABILITY: float | None = None
CHANNEL_MIXER_HALTING_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = (
    LastLayerBiasOptions.DISABLED
)
CHANNEL_MIXER_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
CHANNEL_MIXER_HALTING_STACK_BIAS_FLAG: bool | None = None

#########################################################################
# Channel Mixer Memory Options
# - If `CHANNEL_MIXER_MEMORY_FLAG` is False, the memory-specific parameters below are ignored.
CHANNEL_MIXER_MEMORY_FLAG: bool = False
CHANNEL_MIXER_MEMORY_OPTION: type[DynamicMemoryConfig] = (
    GatedResidualDynamicMemoryConfig
)
CHANNEL_MIXER_MEMORY_POSITION_OPTION: MemoryPositionOptions = (
    MemoryPositionOptions.AFTER_AFFINE
)
CHANNEL_MIXER_MEMORY_TEST_TIME_TRAINING_LEARNING_RATE: float | None = None
CHANNEL_MIXER_MEMORY_TEST_TIME_TRAINING_NUM_INNER_STEPS: int | None = None
## Channel Mixer Memory Stack Options
# - If False, memory stack options inherit the channel mixer stack options.
CHANNEL_MIXER_MEMORY_STACK_INDEPENDENT_FLAG: bool = False
CHANNEL_MIXER_MEMORY_STACK_HIDDEN_DIM: int | None = None
CHANNEL_MIXER_MEMORY_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
CHANNEL_MIXER_MEMORY_STACK_NORMALIZATION: NormalizationOptions | None = None
CHANNEL_MIXER_MEMORY_STACK_NUM_LAYERS: int | None = None
CHANNEL_MIXER_MEMORY_STACK_ACTIVATION: ActivationOptions | None = None
CHANNEL_MIXER_MEMORY_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = (
    None
)
CHANNEL_MIXER_MEMORY_STACK_RESIDUAL_MODEL_FLAG: bool = False
CHANNEL_MIXER_MEMORY_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
CHANNEL_MIXER_MEMORY_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
CHANNEL_MIXER_MEMORY_STACK_DROPOUT_PROBABILITY: float | None = None
CHANNEL_MIXER_MEMORY_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
CHANNEL_MIXER_MEMORY_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
CHANNEL_MIXER_MEMORY_STACK_BIAS_FLAG: bool | None = None

#########################################################################
# Channel Mixer Recurrent Layer Options
# - If `CHANNEL_MIXER_RECURRENT_FLAG` is False, the recurrent-specific parameters below are ignored.
CHANNEL_MIXER_RECURRENT_FLAG: bool = False
CHANNEL_MIXER_RECURRENT_MAX_STEPS: int = 2
CHANNEL_MIXER_RECURRENT_LAYER_NORM_POSITION: LayerNormPositionOptions = (
    LayerNormPositionOptions.DISABLED
)
CHANNEL_MIXER_RECURRENT_NORMALIZATION: NormalizationOptions = (
    NormalizationOptions.LAYER_NORM
)
CHANNEL_MIXER_RECURRENT_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
CHANNEL_MIXER_RECURRENT_RESIDUAL_MODEL_FLAG: bool = False
CHANNEL_MIXER_RECURRENT_RESIDUAL_BLOCK_SIZE: int | None = None
CHANNEL_MIXER_RECURRENT_RESIDUAL_RMS_NORM_EPSILON: float | None = None
## Channel Mixer Recurrent Gate Options
CHANNEL_MIXER_RECURRENT_STACK_GATE_FLAG: bool = False
CHANNEL_MIXER_RECURRENT_GATE_OPTION: LayerGateOptions | None = (
    LayerGateOptions.MULTIPLIER
)
CHANNEL_MIXER_RECURRENT_GATE_ACTIVATION: ActivationOptions | None = (
    ActivationOptions.SIGMOID
)
### Channel Mixer Recurrent Gate Stack Options
# - If False, recurrent gate stack options inherit the channel mixer stack options.
CHANNEL_MIXER_RECURRENT_GATE_STACK_INDEPENDENT_FLAG: bool = False
CHANNEL_MIXER_RECURRENT_GATE_STACK_HIDDEN_DIM: int | None = None
CHANNEL_MIXER_RECURRENT_GATE_STACK_LAYER_NORM_POSITION: (
    LayerNormPositionOptions | None
) = None
CHANNEL_MIXER_RECURRENT_GATE_STACK_NORMALIZATION: NormalizationOptions | None = None
CHANNEL_MIXER_RECURRENT_GATE_STACK_NUM_LAYERS: int | None = None
CHANNEL_MIXER_RECURRENT_GATE_STACK_ACTIVATION: ActivationOptions | None = None
CHANNEL_MIXER_RECURRENT_GATE_STACK_RESIDUAL_CONNECTION_OPTION: (
    type[ResidualConfig] | None
) = None
CHANNEL_MIXER_RECURRENT_GATE_STACK_RESIDUAL_MODEL_FLAG: bool = False
CHANNEL_MIXER_RECURRENT_GATE_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
CHANNEL_MIXER_RECURRENT_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
CHANNEL_MIXER_RECURRENT_GATE_STACK_DROPOUT_PROBABILITY: float | None = None
CHANNEL_MIXER_RECURRENT_GATE_STACK_LAST_LAYER_BIAS_OPTION: (
    LastLayerBiasOptions | None
) = None
CHANNEL_MIXER_RECURRENT_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
CHANNEL_MIXER_RECURRENT_GATE_STACK_BIAS_FLAG: bool | None = None
## Channel Mixer Recurrent Halting Options
CHANNEL_MIXER_RECURRENT_STACK_HALTING_FLAG: bool = False
CHANNEL_MIXER_RECURRENT_HALTING_OPTION: type[HaltingConfig] = StickBreakingConfig
CHANNEL_MIXER_RECURRENT_HALTING_THRESHOLD: float = 0.999
CHANNEL_MIXER_RECURRENT_HALTING_DROPOUT: float = 0.0
CHANNEL_MIXER_RECURRENT_HALTING_HIDDEN_STATE_MODE: HaltingHiddenStateModeOptions = (
    HaltingHiddenStateModeOptions.RAW
)
### Channel Mixer Recurrent Halting Stack Options
# - If False, recurrent halting stack options inherit the channel mixer stack options.
CHANNEL_MIXER_RECURRENT_HALTING_STACK_INDEPENDENT_FLAG: bool = False
CHANNEL_MIXER_RECURRENT_HALTING_STACK_HIDDEN_DIM: int | None = None
CHANNEL_MIXER_RECURRENT_HALTING_STACK_LAYER_NORM_POSITION: (
    LayerNormPositionOptions | None
) = None
CHANNEL_MIXER_RECURRENT_HALTING_STACK_NORMALIZATION: NormalizationOptions | None = None
CHANNEL_MIXER_RECURRENT_HALTING_STACK_NUM_LAYERS: int | None = None
CHANNEL_MIXER_RECURRENT_HALTING_STACK_ACTIVATION: ActivationOptions | None = None
CHANNEL_MIXER_RECURRENT_HALTING_STACK_RESIDUAL_CONNECTION_OPTION: (
    type[ResidualConfig] | None
) = None
CHANNEL_MIXER_RECURRENT_HALTING_STACK_RESIDUAL_MODEL_FLAG: bool = False
CHANNEL_MIXER_RECURRENT_HALTING_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
CHANNEL_MIXER_RECURRENT_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
CHANNEL_MIXER_RECURRENT_HALTING_STACK_DROPOUT_PROBABILITY: float | None = None
CHANNEL_MIXER_RECURRENT_HALTING_STACK_LAST_LAYER_BIAS_OPTION: (
    LastLayerBiasOptions | None
) = None
CHANNEL_MIXER_RECURRENT_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = (
    None
)
CHANNEL_MIXER_RECURRENT_HALTING_STACK_BIAS_FLAG: bool | None = None

# Adaptive expert parameters. These options apply inside experts only; routers,
# patch projection, and classification remain ordinary linear layers.
ADAPTIVE_GENERATOR_STACK_HIDDEN_DIM: int = 32
ADAPTIVE_GENERATOR_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions = (
    LayerNormPositionOptions.BEFORE
)
ADAPTIVE_GENERATOR_STACK_NORMALIZATION: NormalizationOptions = (
    NormalizationOptions.RMS_NORM
)
ADAPTIVE_GENERATOR_STACK_NUM_LAYERS: int = 2
ADAPTIVE_GENERATOR_STACK_ACTIVATION: ActivationOptions = ActivationOptions.GELU
ADAPTIVE_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
ADAPTIVE_GENERATOR_STACK_RESIDUAL_MODEL_FLAG: bool = False
ADAPTIVE_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
ADAPTIVE_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
ADAPTIVE_GENERATOR_STACK_DROPOUT_PROBABILITY: float = 0.0
ADAPTIVE_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions = (
    LastLayerBiasOptions.DEFAULT
)
ADAPTIVE_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool = False
ADAPTIVE_GENERATOR_STACK_BIAS_FLAG: bool = True

WEIGHT_OPTION_FLAG: bool = False
WEIGHT_OPTION: type[DynamicWeightConfig] | None = None
GENERATOR_DEPTH: int = 3
WEIGHT_DECAY_SCHEDULE: WeightDecayScheduleOptions = WeightDecayScheduleOptions.DISABLED
WEIGHT_DECAY_RATE: float = 0.0
WEIGHT_DECAY_WARMUP_BATCHES: int = 0
WEIGHT_NORMALIZATION_OPTION: WeightNormalizationOptions = (
    WeightNormalizationOptions.DISABLED
)
WEIGHT_NORMALIZATION_POSITION_OPTION: WeightNormalizationPositionOptions = (
    WeightNormalizationPositionOptions.BEFORE_OUTER_PRODUCT
)
WEIGHT_BANK_EXPANSION_FACTOR: BankExpansionFactorOptions = (
    BankExpansionFactorOptions.FACTOR_OF_THREE
)
WEIGHT_GENERATOR_STACK_INDEPENDENT_FLAG: bool = False
WEIGHT_GENERATOR_STACK_HIDDEN_DIM: int | None = None
WEIGHT_GENERATOR_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
WEIGHT_GENERATOR_STACK_NORMALIZATION: NormalizationOptions | None = None
WEIGHT_GENERATOR_STACK_NUM_LAYERS: int | None = None
WEIGHT_GENERATOR_STACK_ACTIVATION: ActivationOptions | None = None
WEIGHT_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
WEIGHT_GENERATOR_STACK_RESIDUAL_MODEL_FLAG: bool = False
WEIGHT_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
WEIGHT_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
WEIGHT_GENERATOR_STACK_DROPOUT_PROBABILITY: float | None = None
WEIGHT_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
WEIGHT_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
WEIGHT_GENERATOR_STACK_BIAS_FLAG: bool | None = None

BIAS_OPTION_FLAG: bool = False
BIAS_OPTION: type[DynamicBiasConfig] | None = None
BIAS_DECAY_SCHEDULE: WeightDecayScheduleOptions = WeightDecayScheduleOptions.DISABLED
BIAS_DECAY_RATE: float = 0.0
BIAS_DECAY_WARMUP_BATCHES: int = 0
BIAS_BANK_EXPANSION_FACTOR: BankExpansionFactorOptions = (
    BankExpansionFactorOptions.FACTOR_OF_TWO
)
BIAS_GENERATOR_STACK_INDEPENDENT_FLAG: bool = False
BIAS_GENERATOR_STACK_HIDDEN_DIM: int | None = None
BIAS_GENERATOR_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
BIAS_GENERATOR_STACK_NORMALIZATION: NormalizationOptions | None = None
BIAS_GENERATOR_STACK_NUM_LAYERS: int | None = None
BIAS_GENERATOR_STACK_ACTIVATION: ActivationOptions | None = None
BIAS_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
BIAS_GENERATOR_STACK_RESIDUAL_MODEL_FLAG: bool = False
BIAS_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
BIAS_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
BIAS_GENERATOR_STACK_DROPOUT_PROBABILITY: float | None = None
BIAS_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
BIAS_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
BIAS_GENERATOR_STACK_BIAS_FLAG: bool | None = None

DIAGONAL_OPTION_FLAG: bool = True
DIAGONAL_OPTION: type[DynamicDiagonalConfig] | None = StandardDynamicDiagonalConfig
DIAGONAL_GENERATOR_STACK_INDEPENDENT_FLAG: bool = False
DIAGONAL_GENERATOR_STACK_HIDDEN_DIM: int | None = None
DIAGONAL_GENERATOR_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
DIAGONAL_GENERATOR_STACK_NORMALIZATION: NormalizationOptions | None = None
DIAGONAL_GENERATOR_STACK_NUM_LAYERS: int | None = None
DIAGONAL_GENERATOR_STACK_ACTIVATION: ActivationOptions | None = None
DIAGONAL_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
DIAGONAL_GENERATOR_STACK_RESIDUAL_MODEL_FLAG: bool = False
DIAGONAL_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
DIAGONAL_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
DIAGONAL_GENERATOR_STACK_DROPOUT_PROBABILITY: float | None = None
DIAGONAL_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
DIAGONAL_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
DIAGONAL_GENERATOR_STACK_BIAS_FLAG: bool | None = None

MASK_OPTION_FLAG: bool = False
ROW_MASK_OPTION: type[AxisMaskConfig] | None = None
MASK_THRESHOLD: float = 0.5
MASK_FLOOR: float = 0.0
MASK_TRANSITION_WIDTH: float = 0.1
MASK_SURROGATE_SCALE: float = 10.0
MASK_DIMENSION_OPTION: MaskDimensionOptions = MaskDimensionOptions.COLUMN
MASK_GENERATOR_STACK_INDEPENDENT_FLAG: bool = False
MASK_GENERATOR_STACK_HIDDEN_DIM: int | None = None
MASK_GENERATOR_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
MASK_GENERATOR_STACK_NORMALIZATION: NormalizationOptions | None = None
MASK_GENERATOR_STACK_NUM_LAYERS: int | None = None
MASK_GENERATOR_STACK_ACTIVATION: ActivationOptions | None = None
MASK_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
MASK_GENERATOR_STACK_RESIDUAL_MODEL_FLAG: bool = False
MASK_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
MASK_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
MASK_GENERATOR_STACK_DROPOUT_PROBABILITY: float | None = None
MASK_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
MASK_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
MASK_GENERATOR_STACK_BIAS_FLAG: bool | None = None

# Expert routing
TOP_K: int = 2
NUM_EXPERTS: int = 4
CAPACITY_FACTOR: float = 0.0
DROPPED_TOKEN_BEHAVIOR: DroppedTokenOptions = DroppedTokenOptions.IDENTITY
WEIGHTED_PARAMETERS_FLAG: bool = True
COMPUTE_EXPERT_MIXTURE_FLAG: bool = True
WEIGHTING_POSITION_OPTION: ExpertWeightingPositionOptions = (
    ExpertWeightingPositionOptions.AFTER_EXPERTS
)
ROUTING_INITIALIZATION_MODE: RoutingInitializationMode = RoutingInitializationMode.LAYER

# Sampler
SAMPLER_THRESHOLD: float = 0.0
SAMPLER_FILTER_ABOVE_THRESHOLD: bool = False
SAMPLER_NUM_TOPK_SAMPLES: int = 0
SAMPLER_NORMALIZE_PROBABILITIES_FLAG: bool = True
SAMPLER_NOISY_TOPK_FLAG: bool = False
SAMPLER_COEFFICIENT_OF_VARIATION_LOSS_WEIGHT: float = 0.0
SAMPLER_SWITCH_LOSS_WEIGHT: float = 0.0
SAMPLER_ZERO_CENTRED_LOSS_WEIGHT: float = 0.0
SAMPLER_MUTUAL_INFORMATION_LOSS_WEIGHT: float = 0.0

# Router
ROUTER_NOISY_TOPK_FLAG: bool = False
ROUTER_STACK_HIDDEN_DIM: int = 32
ROUTER_STACK_NUM_LAYERS: int = 2
ROUTER_STACK_ACTIVATION: ActivationOptions = ActivationOptions.GELU
ROUTER_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
ROUTER_STACK_RESIDUAL_MODEL_FLAG: bool = False
ROUTER_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
ROUTER_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
ROUTER_STACK_DROPOUT_PROBABILITY: float = 0.0
ROUTER_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions = (
    LayerNormPositionOptions.DISABLED
)
ROUTER_STACK_NORMALIZATION: NormalizationOptions = NormalizationOptions.RMS_NORM
ROUTER_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions = LastLayerBiasOptions.DEFAULT
ROUTER_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool = False
ROUTER_BIAS_FLAG: bool = STACK_BIAS_FLAG

# Experts
EXPERT_STACK_HIDDEN_DIM: int = 32
EXPERT_STACK_NUM_LAYERS: int = 1
EXPERT_STACK_ACTIVATION: ActivationOptions = ActivationOptions.GELU
EXPERT_STACK_DROPOUT_PROBABILITY: float = 0.0
EXPERT_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions = (
    LayerNormPositionOptions.DISABLED
)
EXPERT_STACK_NORMALIZATION: NormalizationOptions = NormalizationOptions.RMS_NORM
EXPERT_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
EXPERT_STACK_RESIDUAL_MODEL_FLAG: bool = False
EXPERT_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
EXPERT_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
EXPERT_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions = LastLayerBiasOptions.DEFAULT
EXPERT_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool = False
EXPERT_BIAS_FLAG: bool = True

EXPERT_STACK_GATE_FLAG: bool = False
EXPERT_GATE_OPTION: LayerGateOptions | None = LayerGateOptions.MULTIPLIER
EXPERT_GATE_ACTIVATION: ActivationOptions | None = ActivationOptions.SIGMOID
EXPERT_GATE_STACK_INDEPENDENT_FLAG: bool = False
EXPERT_GATE_STACK_HIDDEN_DIM: int | None = None
EXPERT_GATE_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
EXPERT_GATE_STACK_NORMALIZATION: NormalizationOptions | None = None
EXPERT_GATE_STACK_NUM_LAYERS: int | None = None
EXPERT_GATE_STACK_ACTIVATION: ActivationOptions | None = ActivationOptions.TANH
EXPERT_GATE_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
EXPERT_GATE_STACK_RESIDUAL_MODEL_FLAG: bool = False
EXPERT_GATE_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
EXPERT_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
EXPERT_GATE_STACK_DROPOUT_PROBABILITY: float | None = None
EXPERT_GATE_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
EXPERT_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = True
EXPERT_GATE_STACK_BIAS_FLAG: bool | None = True

EXPERT_STACK_HALTING_FLAG: bool = False
EXPERT_HALTING_OPTION: type[HaltingConfig] = StickBreakingConfig
EXPERT_HALTING_THRESHOLD: float = 0.999
EXPERT_HALTING_DROPOUT: float = 0.0
EXPERT_HALTING_HIDDEN_STATE_MODE: HaltingHiddenStateModeOptions = (
    HaltingHiddenStateModeOptions.RAW
)
EXPERT_HALTING_STACK_INDEPENDENT_FLAG: bool = False
EXPERT_HALTING_STACK_HIDDEN_DIM: int | None = None
EXPERT_HALTING_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
EXPERT_HALTING_STACK_NORMALIZATION: NormalizationOptions | None = None
EXPERT_HALTING_STACK_NUM_LAYERS: int | None = None
EXPERT_HALTING_STACK_ACTIVATION: ActivationOptions | None = None
EXPERT_HALTING_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
EXPERT_HALTING_STACK_RESIDUAL_MODEL_FLAG: bool = False
EXPERT_HALTING_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
EXPERT_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
EXPERT_HALTING_STACK_DROPOUT_PROBABILITY: float | None = None
EXPERT_HALTING_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
EXPERT_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
EXPERT_HALTING_STACK_BIAS_FLAG: bool | None = None

EXPERT_MEMORY_FLAG: bool = False
EXPERT_MEMORY_OPTION: type[DynamicMemoryConfig] = GatedResidualDynamicMemoryConfig
EXPERT_MEMORY_POSITION_OPTION: MemoryPositionOptions = (
    MemoryPositionOptions.AFTER_AFFINE
)
EXPERT_MEMORY_TEST_TIME_TRAINING_LEARNING_RATE: float | None = None
EXPERT_MEMORY_TEST_TIME_TRAINING_NUM_INNER_STEPS: int | None = None
EXPERT_MEMORY_STACK_INDEPENDENT_FLAG: bool = False
EXPERT_MEMORY_STACK_HIDDEN_DIM: int | None = None
EXPERT_MEMORY_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
EXPERT_MEMORY_STACK_NORMALIZATION: NormalizationOptions | None = None
EXPERT_MEMORY_STACK_NUM_LAYERS: int | None = None
EXPERT_MEMORY_STACK_ACTIVATION: ActivationOptions | None = None
EXPERT_MEMORY_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
EXPERT_MEMORY_STACK_RESIDUAL_MODEL_FLAG: bool = False
EXPERT_MEMORY_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
EXPERT_MEMORY_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
EXPERT_MEMORY_STACK_DROPOUT_PROBABILITY: float | None = None
EXPERT_MEMORY_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
EXPERT_MEMORY_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
EXPERT_MEMORY_STACK_BIAS_FLAG: bool | None = None

EXPERT_RECURRENT_FLAG: bool = False
EXPERT_RECURRENT_MAX_STEPS: int = 3
EXPERT_RECURRENT_LAYER_NORM_POSITION: LayerNormPositionOptions = (
    LayerNormPositionOptions.DISABLED
)
EXPERT_RECURRENT_NORMALIZATION: NormalizationOptions = NormalizationOptions.LAYER_NORM
EXPERT_RECURRENT_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = None
EXPERT_RECURRENT_RESIDUAL_MODEL_FLAG: bool = False
EXPERT_RECURRENT_RESIDUAL_BLOCK_SIZE: int | None = None
EXPERT_RECURRENT_RESIDUAL_RMS_NORM_EPSILON: float | None = None
EXPERT_RECURRENT_STACK_GATE_FLAG: bool = False
EXPERT_RECURRENT_GATE_OPTION: LayerGateOptions | None = LayerGateOptions.MULTIPLIER
EXPERT_RECURRENT_GATE_ACTIVATION: ActivationOptions | None = ActivationOptions.SIGMOID
EXPERT_RECURRENT_GATE_STACK_INDEPENDENT_FLAG: bool = False
EXPERT_RECURRENT_GATE_STACK_HIDDEN_DIM: int | None = None
EXPERT_RECURRENT_GATE_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = None
EXPERT_RECURRENT_GATE_STACK_NORMALIZATION: NormalizationOptions | None = None
EXPERT_RECURRENT_GATE_STACK_NUM_LAYERS: int | None = None
EXPERT_RECURRENT_GATE_STACK_ACTIVATION: ActivationOptions | None = None
EXPERT_RECURRENT_GATE_STACK_RESIDUAL_CONNECTION_OPTION: type[ResidualConfig] | None = (
    None
)
EXPERT_RECURRENT_GATE_STACK_RESIDUAL_MODEL_FLAG: bool = False
EXPERT_RECURRENT_GATE_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
EXPERT_RECURRENT_GATE_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
EXPERT_RECURRENT_GATE_STACK_DROPOUT_PROBABILITY: float | None = None
EXPERT_RECURRENT_GATE_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = None
EXPERT_RECURRENT_GATE_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
EXPERT_RECURRENT_GATE_STACK_BIAS_FLAG: bool | None = None
EXPERT_RECURRENT_STACK_HALTING_FLAG: bool = False
EXPERT_RECURRENT_HALTING_OPTION: type[HaltingConfig] = StickBreakingConfig
EXPERT_RECURRENT_HALTING_THRESHOLD: float = 0.999
EXPERT_RECURRENT_HALTING_DROPOUT: float = 0.0
EXPERT_RECURRENT_HALTING_HIDDEN_STATE_MODE: HaltingHiddenStateModeOptions = (
    HaltingHiddenStateModeOptions.RAW
)
EXPERT_RECURRENT_HALTING_STACK_INDEPENDENT_FLAG: bool = False
EXPERT_RECURRENT_HALTING_STACK_HIDDEN_DIM: int | None = None
EXPERT_RECURRENT_HALTING_STACK_LAYER_NORM_POSITION: LayerNormPositionOptions | None = (
    None
)
EXPERT_RECURRENT_HALTING_STACK_NORMALIZATION: NormalizationOptions | None = None
EXPERT_RECURRENT_HALTING_STACK_NUM_LAYERS: int | None = None
EXPERT_RECURRENT_HALTING_STACK_ACTIVATION: ActivationOptions | None = None
EXPERT_RECURRENT_HALTING_STACK_RESIDUAL_CONNECTION_OPTION: (
    type[ResidualConfig] | None
) = None
EXPERT_RECURRENT_HALTING_STACK_RESIDUAL_MODEL_FLAG: bool = False
EXPERT_RECURRENT_HALTING_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
EXPERT_RECURRENT_HALTING_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
EXPERT_RECURRENT_HALTING_STACK_DROPOUT_PROBABILITY: float | None = None
EXPERT_RECURRENT_HALTING_STACK_LAST_LAYER_BIAS_OPTION: LastLayerBiasOptions | None = (
    None
)
EXPERT_RECURRENT_HALTING_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
EXPERT_RECURRENT_HALTING_STACK_BIAS_FLAG: bool | None = None


# ==============================================================================
# Main Adaptive Generation
# ==============================================================================
WEIGHT_INPUT_FACTOR_SOURCE: LowRankFactorSourceOptions | None = None
WEIGHT_OUTPUT_FACTOR_SOURCE: LowRankFactorSourceOptions | None = None
WEIGHT_MIXTURE_NUM_EXPERTS: int | None = None
BIAS_MIXTURE_NUM_EXPERTS: int | None = None
WEIGHT_MIXTURE_TOP_K: int | None = None
BIAS_MIXTURE_TOP_K: int | None = None
WEIGHT_MIXTURE_NORMALIZE_PROBABILITIES_FLAG: bool | None = None
BIAS_MIXTURE_NORMALIZE_PROBABILITIES_FLAG: bool | None = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_INDEPENDENT_FLAG: bool = False
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_HIDDEN_DIM: int | None = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_LAYER_NORM_POSITION: (
    LayerNormPositionOptions | None
) = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_NORMALIZATION: NormalizationOptions | None = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_NUM_LAYERS: int | None = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_ACTIVATION: ActivationOptions | None = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION: (
    type[ResidualConfig] | None
) = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_RESIDUAL_MODEL_FLAG: bool = False
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_DROPOUT_PROBABILITY: float | None = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION: (
    LastLayerBiasOptions | None
) = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
WEIGHT_INPUT_FACTOR_GENERATOR_STACK_BIAS_FLAG: bool | None = None
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_INDEPENDENT_FLAG: bool = False
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_HIDDEN_DIM: int | None = None
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_LAYER_NORM_POSITION: (
    LayerNormPositionOptions | None
) = None
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_NORMALIZATION: NormalizationOptions | None = None
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_NUM_LAYERS: int | None = None
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_ACTIVATION: ActivationOptions | None = None
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION: (
    type[ResidualConfig] | None
) = None
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_RESIDUAL_MODEL_FLAG: bool = False
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_DROPOUT_PROBABILITY: float | None = None
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION: (
    LastLayerBiasOptions | None
) = None
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = (
    None
)
WEIGHT_OUTPUT_FACTOR_GENERATOR_STACK_BIAS_FLAG: bool | None = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_INDEPENDENT_FLAG: bool = False
WEIGHT_COEFFICIENT_GENERATOR_STACK_HIDDEN_DIM: int | None = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_LAYER_NORM_POSITION: (
    LayerNormPositionOptions | None
) = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_NORMALIZATION: NormalizationOptions | None = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_NUM_LAYERS: int | None = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_ACTIVATION: ActivationOptions | None = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION: (
    type[ResidualConfig] | None
) = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_RESIDUAL_MODEL_FLAG: bool = False
WEIGHT_COEFFICIENT_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_DROPOUT_PROBABILITY: float | None = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION: (
    LastLayerBiasOptions | None
) = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
WEIGHT_COEFFICIENT_GENERATOR_STACK_BIAS_FLAG: bool | None = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_INDEPENDENT_FLAG: bool = False
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_INDEPENDENT_FLAG: bool = False
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_HIDDEN_DIM: int | None = None
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_HIDDEN_DIM: int | None = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_LAYER_NORM_POSITION: (
    LayerNormPositionOptions | None
) = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_NORMALIZATION: NormalizationOptions | None = None
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_LAYER_NORM_POSITION: (
    LayerNormPositionOptions | None
) = None
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_NORMALIZATION: NormalizationOptions | None = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_NUM_LAYERS: int | None = None
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_NUM_LAYERS: int | None = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_ACTIVATION: ActivationOptions | None = None
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_ACTIVATION: ActivationOptions | None = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION: (
    type[ResidualConfig] | None
) = None
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_RESIDUAL_CONNECTION_OPTION: (
    type[ResidualConfig] | None
) = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_RESIDUAL_MODEL_FLAG: bool = False
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_RESIDUAL_MODEL_FLAG: bool = False
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_RESIDUAL_BLOCK_SIZE: int | None = None
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_RESIDUAL_RMS_NORM_EPSILON: float | None = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_DROPOUT_PROBABILITY: float | None = None
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_DROPOUT_PROBABILITY: float | None = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION: (
    LastLayerBiasOptions | None
) = None
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_LAST_LAYER_BIAS_OPTION: (
    LastLayerBiasOptions | None
) = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = (
    None
)
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_APPLY_OUTPUT_POSTPROCESSING_FLAG: bool | None = None
WEIGHT_MIXTURE_ROUTER_GENERATOR_STACK_BIAS_FLAG: bool | None = None
BIAS_MIXTURE_ROUTER_GENERATOR_STACK_BIAS_FLAG: bool | None = None

# Main Grouping
GROUPING_SCOPE: AdaptiveParameterGroupingScopeOptions | None = None
GROUP_COUNT: int | None = None
CHUNK_SIZE: int | None = None
GROUPING_SEQUENCE_LENGTH: int | None = None
GROUPING_INPUT_ORDER: AdaptiveParameterInputOrderOptions | None = None
GROUPING_METHOD: type[GroupingConfig] | None = None
GROUPING_SUMMARY_NORMALIZATION: SummaryNormalizationOptions | None = None
GROUPING_MODEL_CONFIG: ConfigBase | None = None
GROUPING_ATTENTION_HIDDEN_DIM: int | None = None
GROUPING_RMS_NORM_EPSILON: float | None = None


# Channel Mixer Grouping
CHANNEL_MIXER_GROUPING_SCOPE: AdaptiveParameterGroupingScopeOptions | None = None
CHANNEL_MIXER_GROUP_COUNT: int | None = None
CHANNEL_MIXER_CHUNK_SIZE: int | None = None
CHANNEL_MIXER_GROUPING_SEQUENCE_LENGTH: int | None = None
CHANNEL_MIXER_GROUPING_INPUT_ORDER: AdaptiveParameterInputOrderOptions | None = None
CHANNEL_MIXER_GROUPING_METHOD: type[GroupingConfig] | None = None
CHANNEL_MIXER_GROUPING_SUMMARY_NORMALIZATION: SummaryNormalizationOptions | None = None
CHANNEL_MIXER_GROUPING_MODEL_CONFIG: ConfigBase | None = None
CHANNEL_MIXER_GROUPING_ATTENTION_HIDDEN_DIM: int | None = None
CHANNEL_MIXER_GROUPING_RMS_NORM_EPSILON: float | None = None
