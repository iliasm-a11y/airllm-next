import importlib
class AutoConfig:
    """Load Transformers config support only when upstream dispatch needs it."""
    @staticmethod
    def from_pretrained(*args, **kwargs):
        from transformers import AutoConfig as HFConfig
        return HFConfig.from_pretrained(*args, **kwargs)

from sys import platform

is_on_mac_os = False

if platform == "darwin":
    is_on_mac_os = True


# Architectures that need a dedicated AirLLM subclass because of a non-standard module layout
# (custom remote-code models). Everything else uses the generic AirLLMBaseModel, which streams any
# standard *ForCausalLM (model.model.layers + lm_head / norm) and lets transformers own the
# forward pass, so newly released architectures work without code changes.
ARCH_OVERRIDES = {
    "ChatGLMModel": "AirLLMChatGLM",
    "ChatGLMForConditionalGeneration": "AirLLMChatGLM",
    "QWenLMHeadModel": "AirLLMQWen",
    "BaichuanForCausalLM": "AirLLMBaichuan",
    "BaiChuanForCausalLM": "AirLLMBaichuan",
    "InternLMForCausalLM": "AirLLMInternLM",
    "KimiK3ForConditionalGeneration": "AirLLMKimiK3",
    "Qwen3_5ForConditionalGeneration": "AirLLMQwen3_5",
    "Qwen4ExpForConditionalGeneration": "AirLLMQwen4Exp",
}

# On macOS every model goes through AirLLMLlamaMlx, an MLX port of the Llama decoder block, so only
# checkpoints with that layout can run there. Mistral uses the same block and weight names.
MLX_ARCHITECTURES = {"LlamaForCausalLM", "MistralForCausalLM"}


class AutoModel:
    def __init__(self):
        raise EnvironmentError(
            "AutoModel is designed to be instantiated "
            "using the `AutoModel.from_pretrained(pretrained_model_name_or_path)` method."
        )

    @classmethod
    def get_architecture(cls, pretrained_model_name_or_path, *inputs, **kwargs):
        if 'hf_token' in kwargs:
            config = AutoConfig.from_pretrained(pretrained_model_name_or_path, trust_remote_code=True,
                                                token=kwargs['hf_token'])
        else:
            config = AutoConfig.from_pretrained(pretrained_model_name_or_path, trust_remote_code=True)

        architectures = getattr(config, "architectures", None) or []
        return architectures[0] if architectures else ""

    @classmethod
    def get_module_class(cls, pretrained_model_name_or_path, *inputs, **kwargs):
        arch = AutoModel.get_architecture(pretrained_model_name_or_path, *inputs, **kwargs)

        cls_name = ARCH_OVERRIDES.get(arch)
        if cls_name is None:
            print(f"using generic AirLLM streaming model for architecture: {arch or 'unknown'}")
            cls_name = "AirLLMBaseModel"
        return "airllm", cls_name

    @classmethod
    def from_pretrained(cls, pretrained_model_name_or_path, *inputs, **kwargs):
        if kwargs.get('backend') in ('next', 'mlx-next'):
            kwargs.pop('backend')
            if inputs: raise TypeError('Next accepts keyword options after the local checkpoint path')
            from .nextgen.runtime import AirLLMNextModel
            return AirLLMNextModel(pretrained_model_name_or_path, **kwargs)
        # Opt in explicitly; preserve all upstream defaults and model overrides.
        ultra = kwargs.pop('ultra', None)
        backend = kwargs.pop('backend', None)
        if backend == 'mlx-ultra':
            from .ultra.mlx_runtime import MlxLlamaUltra
            return MlxLlamaUltra(pretrained_model_name_or_repo_id=pretrained_model_name_or_path,
                                 ultra=ultra, **kwargs)
        if ultra is not None or backend == 'ultra':
            if inputs:
                raise TypeError('Ultra accepts keyword options after the local checkpoint path')
            from .ultra.runtime import AirLLMUltraModel
            return AirLLMUltraModel(pretrained_model_name_or_path, ultra=ultra, **kwargs)
        if backend not in (None, 'upstream'):
            raise ValueError(f'Unknown AirLLM backend: {backend}')

        if is_on_mac_os:
            # Check this before AirLLMLlamaMlx downloads and splits the whole checkpoint, otherwise an
            # unsupported model only fails (or gives garbage) after that is done.
            arch = AutoModel.get_architecture(pretrained_model_name_or_path, *inputs, **kwargs)
            if arch and arch not in MLX_ARCHITECTURES:
                raise ValueError(
                    f"{arch} is not supported on macOS yet. The macOS backend (MLX) only runs "
                    f"Llama-style models: {', '.join(sorted(MLX_ARCHITECTURES))}."
                )
            from .airllm_llama_mlx import AirLLMLlamaMlx
            return AirLLMLlamaMlx(pretrained_model_name_or_path, *inputs, **kwargs)

        module, class_name = AutoModel.get_module_class(pretrained_model_name_or_path, *inputs, **kwargs)
        module = importlib.import_module(module)
        class_ = getattr(module, class_name)
        return class_(pretrained_model_name_or_path, *inputs, **kwargs)
