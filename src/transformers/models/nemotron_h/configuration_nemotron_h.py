
from huggingface_hub.dataclasses import strict

from ...configuration_utils import PreTrainedConfig, remap_legacy_layer_types
from ...utils import auto_docstring, logging


logger = logging.get_logger(__name__)


@auto_docstring(checkpoint="nvidia/NVIDIA-Nemotron-3-Nano-30B-A3B-BF16")
@strict
class NemotronHConfig(PreTrainedConfig):

    model_type = "nemotron_h"
    attribute_map = {"layer_types": "layers_block_type", "num_local_experts": "n_routed_experts"}
    keys_to_ignore_at_inference = ["past_key_values"]

    vocab_size: int = 131072
    hidden_size: int = 4096
    layers_block_type: list[str] | None = None
    tie_word_embeddings: bool = False
    use_cache: bool = True
    num_logits_to_keep: int = 1
    pad_token_id: int | None = 0
    bos_token_id: int | None = 1
    eos_token_id: int | list[int] | None = 2
    num_attention_heads: int = 32
    num_key_value_heads: int = 8
    head_dim: int = 128
    max_position_embeddings: int = 4096
    attention_bias: bool = False
    attention_dropout: float | int = 0.0
    sliding_window: int | None = None
    intermediate_size: int = 21504
    mlp_hidden_act: str = "relu2"
    mlp_bias: bool = False
    use_mamba_kernels: bool = True
    ssm_state_size: int = 128
    mamba_num_heads: int = 128
    mamba_head_dim: int = 64
    mamba_hidden_act: str = "silu"
    n_groups: int = 8
    conv_kernel: int = 4
    expand: int = 2
    time_step_min: float = 0.001
    time_step_max: float = 0.1
    time_step_limit: list[float] | tuple[float, ...] = (0.0, float("inf"))
    time_step_floor: float = 1e-4
    use_conv_bias: bool = True
    chunk_size: int = 128
    mamba_proj_bias: bool = False
    mamba_ssm_cache_dtype: str = "float32"
    n_routed_experts: int = 8
    n_shared_experts: int = 1
    moe_intermediate_size: int = 7688
    moe_shared_expert_intermediate_size: int = 7688
    moe_latent_size: int | None = None
    moe_shared_expert_overlap: bool = True
    num_experts_per_tok: int = 2
    routed_scaling_factor: float | int = 1.0
    n_group: int = 1
    topk_group: int = 1
    norm_topk_prob: bool = True
    num_nextn_predict_layers: int = 0
    mtp_layers_block_type: list[str] | None = None
    use_bias: bool = False
    initializer_range: float = 0.02
    layer_norm_epsilon: float = 1e-5
    residual_in_fp32: bool = False
    hidden_dropout: float | int = 0.0
    rescale_prenorm_residual: bool = True

    def __post_init__(self, **kwargs):
        self.n_groups = kwargs.pop("mamba_n_groups") if "mamba_n_groups" in kwargs else self.n_groups
        self.conv_kernel = kwargs.pop("mamba_d_conv") if "mamba_d_conv" in kwargs else self.conv_kernel
        self.expand = kwargs.pop("mamba_expand") if "mamba_expand" in kwargs else self.expand
        self.time_step_min = kwargs.pop("mamba_dt_min") if "mamba_dt_min" in kwargs else self.time_step_min
        self.time_step_max = kwargs.pop("mamba_dt_max") if "mamba_dt_max" in kwargs else self.time_step_max
        self.time_step_limit = kwargs.pop("mamba_dt_limit") if "mamba_dt_limit" in kwargs else self.time_step_limit
        self.time_step_floor = (
            kwargs.pop("mamba_dt_init_floor") if "mamba_dt_init_floor" in kwargs else self.time_step_floor
        )
        self.use_conv_bias = kwargs.pop("mamba_conv_bias") if "mamba_conv_bias" in kwargs else self.use_conv_bias
        self.chunk_size = kwargs.pop("mamba_chunk_size") if "mamba_chunk_size" in kwargs else self.chunk_size

        if "hybrid_override_pattern" in kwargs:
            pattern = kwargs.pop("hybrid_override_pattern")
            if self.layer_types is None:
                self.layer_types = self._pattern_to_list(pattern)
        elif self.layer_types is None:
            self.layer_types = ["linear_attention", "moe", "full_attention", "mlp"]
        else:
            self.layer_types = remap_legacy_layer_types(self.layer_types)

        if self.num_hidden_layers is not None:
            if len(self.layer_types) != self.num_hidden_layers:
                logger.warning(
                    f"num_hidden_layers ({self.num_hidden_layers}) is deprecated and doesn't match "
                    f"layer_types length ({len(self.layer_types)}). Using layers_block_type length."
                )

        if self.mtp_layers_block_type is None:
            self.mtp_layers_block_type = ["full_attention", "moe"]
        else:
            self.mtp_layers_block_type = remap_legacy_layer_types(self.mtp_layers_block_type)

        if "mtp_hybrid_override_pattern" in kwargs:
            pattern = kwargs.pop("mtp_hybrid_override_pattern")
            if self.mtp_layers_block_type == ["full_attention", "moe"]:
                self.mtp_layers_block_type = self._pattern_to_list(pattern)

        if self.num_key_value_heads is None:
            self.num_key_value_heads = self.num_attention_heads

        super().__post_init__(**kwargs)

    @staticmethod
    def validate_layer_type(self):
        """
        Validate layers_block_type list.
        """
        if not isinstance(self.layer_types, list):
            raise ValueError(f"`layers_block_type` must be a list of strings. Got type: {type(self.layer_types)}")

        valid_types = {"full_attention", "linear_attention", "moe", "mlp"}
        if not all(block_type in valid_types for block_type in self.layer_types):
            invalid = set(self.layer_types) - valid_types
            raise ValueError(f"`layers_block_type` contains invalid types: {invalid}. Must be one of: {valid_types}")

        if self.num_nextn_predict_layers > 0:
            if self.mtp_layers_block_type is None:
                raise ValueError(
                    "mtp_layers_block_type is required when num_nextn_predict_layers > 0. "
                    "Please provide an explicit list of layer types for MTP layers. "
                    "Example: mtp_layers_block_type=['attention', 'moe']"
                )

            if not isinstance(self.mtp_layers_block_type, list):
                raise ValueError(
                    f"`mtp_layers_block_type` must be a list of strings. Got type: {type(self.mtp_layers_block_type)}"
                )

            if not all(block_type in valid_types for block_type in self.mtp_layers_block_type):
                invalid = set(self.mtp_layers_block_type) - valid_types
                raise ValueError(
                    f"`mtp_layers_block_type` contains invalid types: {invalid}. Must be one of: {valid_types}"
                )

    @property
    def num_hidden_layers(self) -> int:
        pass

    @num_hidden_layers.setter
    def num_hidden_layers(self, value):
        """
        Setter for backward compatibility when loading configs.
        The value is ignored since num_hidden_layers is computed from layers_block_type.
        """
        pass

    @property
    def hybrid_override_pattern(self) -> str:
        pass

    @property
    def mtp_hybrid_override_pattern(self) -> str:
        pass

    @staticmethod
    def _list_to_pattern(layers_list: list) -> str:
        pass

    @staticmethod
    def _pattern_to_list(pattern: str) -> list:
        """Convert pattern string to list of layer types (for backward compatibility)."""
        pattern_mapping = {"M": "linear_attention", "E": "moe", "*": "full_attention", "-": "mlp"}
        return [pattern_mapping[char] for char in pattern]


__all__ = ["NemotronHConfig"]
