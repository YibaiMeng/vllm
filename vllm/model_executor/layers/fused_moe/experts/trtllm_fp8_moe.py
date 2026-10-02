# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright contributors to the vLLM project

import contextlib

import torch

import vllm.envs as envs
import vllm.model_executor.layers.fused_moe.modular_kernel as mk
from vllm.logger import init_logger
from vllm.model_executor.layers.fused_moe.activation import MoEActivation
from vllm.model_executor.layers.fused_moe.config import (
    FusedMoEConfig,
    FusedMoEParallelConfig,
    FusedMoEQuantConfig,
    RoutingMethodType,
)
from vllm.model_executor.layers.fused_moe.experts.trtllm_fused_routing import (
    FusedRouterInput,
    fused_router_routing_supported,
    prepare_fused_router_routing,
    run_fused_router_routing,
)
from vllm.model_executor.layers.fused_moe.flashinfer_exact_routing import (
    single_cta_routing_covers,
)
from vllm.model_executor.layers.fused_moe.moe_output import (
    UnfinalizedMoEOutput,
    convert_flashinfer_moe_output,
)
from vllm.model_executor.layers.fused_moe.topk_weight_and_reduce import (
    TopKWeightAndReduceNoOP,
)
from vllm.model_executor.layers.fused_moe.utils import (
    fi_moe_largest_bucket,
)
from vllm.model_executor.layers.quantization.utils.flashinfer_utils import (
    activation_to_flashinfer_int,
)
from vllm.model_executor.layers.quantization.utils.quant_utils import (
    QuantKey,
    kFp8Dynamic128Sym,
    kFp8Static128BlockSym,
    kFp8StaticTensorSym,
    kMxfp8Dynamic,
    kMxfp8Static,
)
from vllm.platforms import current_platform
from vllm.utils.flashinfer import has_flashinfer_trtllm_fused_moe

logger = init_logger(__name__)


# Routing methods FlashInfer serves with routingCustom (Block / DynBlock kernels
# at T <= 16). DeepSeekV3 qualifies only without expert groups (n_group <= 1);
# grouped DeepSeekV3 runs routingDeepSeek (Cluster kernel) and Llama4 its own
# routing, so neither is allowed.
_SM107_MOE_PDL_ROUTING = frozenset(
    {
        RoutingMethodType.Default,
        RoutingMethodType.Renormalize,
        RoutingMethodType.RenormalizeNaive,
        RoutingMethodType.TopK,
        RoutingMethodType.SigmoidRenorm,
        RoutingMethodType.Sigmoid,
        RoutingMethodType.MiniMax2,
        RoutingMethodType.DeepSeekV3,
    }
)
# SigmoidBias policy (DeepSeekV3 with n_group <= 1, MiniMax2): top_k 23-32
# dispatches to Tier<1024, 32>, whose T = 5..16 calls take the Cluster path.
_SM107_MOE_PDL_SIGMOID_BIAS_MAX_TOP_K = 22


def _sm107_moe_pdl_allowed(
    num_tokens: int,
    num_experts: int,
    hidden_size: int,
    routing_method: RoutingMethodType,
    n_group: int | None,
    top_k: int,
    deferred: bool = False,
) -> bool:
    """Whether one trtllm-gen MoE call stays on the kernels the SM107 PDL
    opt-in was validated for (see ``_sm107_moe_pdl``); platform not checked.

    ``deferred``: this call skips FlashInfer's finalize (``do_finalize=False``),
    so finalizeKernelVecLoad (reads routing outputs before its wait) cannot run
    and the finalize-grid bound does not apply.
    """
    if not (
        0 < num_tokens <= envs.VLLM_FI_SM107_MOE_PDL_MAX_TOKENS
        and num_experts <= 512
        and (deferred or (hidden_size + 255) // 256 * num_tokens < 1184)
        and routing_method in _SM107_MOE_PDL_ROUTING
    ):
        return False
    if routing_method == RoutingMethodType.DeepSeekV3 and (n_group or 0) > 1:
        return False
    if num_tokens <= 16:
        sigmoid_bias = routing_method in (
            RoutingMethodType.DeepSeekV3,
            RoutingMethodType.MiniMax2,
        )
        return not sigmoid_bias or top_k <= _SM107_MOE_PDL_SIGMOID_BIAS_MAX_TOP_K
    # Above 16 tokens the stock permutation is the Cluster / cooperative kernel.
    # Only calls whose permutation the single-CTA kernel of the patched module
    # runs instead (flashinfer_exact_routing; hooked in routingCustom with the
    # Renormalize policy) keep a pipeline of kernels that all wait first:
    # BlockScores / HistogramScores, single-CTA permutation, FC1, FC2, and
    # finalizeKernel or no FlashInfer finalize.
    if routing_method not in (
        RoutingMethodType.Renormalize,
        RoutingMethodType.RenormalizeNaive,
    ):
        return False
    return single_cta_routing_covers(num_tokens, num_experts, top_k)


@contextlib.contextmanager
def _sm107_moe_pdl(
    num_tokens: int,
    num_experts: int,
    hidden_size: int,
    routing_method: RoutingMethodType,
    n_group: int | None,
    top_k: int,
    deferred: bool = False,
):
    """Opt into PDL for one trtllm-gen MoE call on SM107.

    FlashInfer 0.6.18 (PR #4806) forces ``enable_pdl=False`` for the whole
    trtllm-gen MoE pipeline on CC 10.7 after crashes in Cluster routing. With
    routingCustom-family routing (no expert groups; top_k <= 22 for the
    SigmoidBias policy), up to 16 tokens and <= 512 experts, routing runs the
    Block/DynBlock kernels (not Cluster/Coop) and finalize runs finalizeKernel
    (not finalizeKernelVecLoad); together with bmm FC1/FC2 they all wait on
    their producer before reading it. Larger calls qualify only where the
    single-CTA routing permutation replaces Cluster/Coop (see
    ``_sm107_moe_pdl_allowed``). Enabled by VLLM_FI_SM107_MOE_PDL_MAX_TOKENS
    (default 0: FlashInfer behaviour).
    """
    if not (
        _sm107_moe_pdl_allowed(
            num_tokens,
            num_experts,
            hidden_size,
            routing_method,
            n_group,
            top_k,
            deferred=deferred,
        )
        and current_platform.is_device_capability(107)
    ):
        yield
        return
    import flashinfer.fused_moe.core as fi_moe_core
    from flashinfer.utils import device_support_pdl

    gate = fi_moe_core._device_support_moe_pdl
    fi_moe_core._device_support_moe_pdl = device_support_pdl
    try:
        yield
    finally:
        fi_moe_core._device_support_moe_pdl = gate


def prepare_deepseek_fp8_x_sf(x: torch.Tensor, x_sf: torch.Tensor) -> torch.Tensor:
    """Validate DeepSeek Blockwise FP8 tensors and return TRTLLM layout."""
    if x.dtype != current_platform.fp8_dtype():
        raise ValueError(
            f"DeepSeekFp8 activations must use the platform E4M3 dtype; got {x.dtype}"
        )
    if x.ndim != 2 or x.shape[1] % 128 != 0:
        raise ValueError(
            "DeepSeekFp8 activations must be [M,K] with K divisible by 128; "
            f"got {tuple(x.shape)}"
        )
    expected_shape = (x.shape[0], x.shape[1] // 128)
    if x_sf.dtype != torch.float32 or tuple(x_sf.shape) != expected_shape:
        raise ValueError(
            "DeepSeekFp8 activation scales must be FP32 [M,K/128]; "
            f"expected {expected_shape}, got dtype={x_sf.dtype}, "
            f"shape={tuple(x_sf.shape)}"
        )
    # FlashInfer TRTLLM-gen consumes [K/128,M] for DeepSeekFp8/BlockMajorK.
    return x_sf.t().contiguous()


class TrtLlmFp8ExpertsBase:
    """Fp8 TRTLLM-Gen MoE kernels. Shared base for modular and monolithic
    interfaces.
    """

    @staticmethod
    def is_supported_config(
        cls: type[mk.FusedMoEExperts],
        moe_config: FusedMoEConfig,
        weight_key: QuantKey | None,
        activation_key: QuantKey | None,
        activation_format: mk.FusedMoEActivationFormat,
    ) -> tuple[bool, str | None]:
        supported, reason = mk.FusedMoEExperts.is_supported_config(
            cls,
            moe_config,
            weight_key,
            activation_key,
            activation_format,
        )
        if not supported:
            return supported, reason
        if (
            moe_config.swiglu_limit is not None
            or moe_config.swiglu_alpha is not None
            or moe_config.swiglu_beta is not None
        ) and (
            (weight_key, activation_key)
            not in (
                (kMxfp8Static, kMxfp8Dynamic),
                (kFp8Static128BlockSym, kFp8Dynamic128Sym),
            )
            or moe_config.activation
            not in (
                MoEActivation.SILU,
                MoEActivation.SWIGLUOAI_UNINTERLEAVE,
            )
        ):
            return False, (
                "the TRTLLM FP8 kernels apply the SwiGLU alpha/beta/clamp "
                "parameters only for block-scaled weights with a SwiGLU "
                f"activation, but got {weight_key} and {moe_config.activation}"
            )
        if moe_config.num_experts > 2048:
            return False, (
                "FlashInfer TRTLLM routing supports at most 2048 experts, "
                f"but got {moe_config.num_experts}"
            )
        return True, None

    def __init__(
        self,
        moe_config: FusedMoEConfig,
        quant_config: FusedMoEQuantConfig,
    ):
        self.routing_method_type = moe_config.routing_method
        self.topk = moe_config.experts_per_token
        self.intermediate_size_per_partition = (
            moe_config.intermediate_size_per_partition
        )
        self.hidden_dim = moe_config.hidden_dim
        self.local_num_experts = moe_config.num_local_experts
        self.ep_rank = moe_config.moe_parallel_config.ep_rank

        self.moe_config = moe_config
        self.quant_config = quant_config

        # Per-expert SwiGLU parameters from quant_config (MXFP8 + Swiglu only).
        device = torch.accelerator.current_device_index()
        if quant_config.gemm1_alpha is not None:
            self.gemm1_alpha = torch.tensor(
                [quant_config.gemm1_alpha] * self.local_num_experts,
                dtype=torch.float32,
                device=device,
            )
        else:
            self.gemm1_alpha = None

        if quant_config.gemm1_beta is not None:
            self.gemm1_beta = torch.tensor(
                [quant_config.gemm1_beta] * self.local_num_experts,
                dtype=torch.float32,
                device=device,
            )
        else:
            self.gemm1_beta = None

        if quant_config.gemm1_clamp_limit is not None:
            self.gemm1_clamp_limit = torch.tensor(
                [quant_config.gemm1_clamp_limit] * self.local_num_experts,
                dtype=torch.float32,
                device=device,
            )
        else:
            self.gemm1_clamp_limit = None

    @staticmethod
    def activation_format() -> mk.FusedMoEActivationFormat:
        return mk.FusedMoEActivationFormat.Standard

    @staticmethod
    def _supports_current_device() -> bool:
        """Supports only Blackwell-family GPUs."""
        p = current_platform
        return (
            p.is_cuda()
            and p.is_device_capability_family(100)
            and has_flashinfer_trtllm_fused_moe()
        )

    @staticmethod
    def _supports_no_act_and_mul() -> bool:
        """Does not support non-gated MoE (i.e. Nanotron-3-Nano)."""
        return True

    @staticmethod
    def _supports_activation(activation: MoEActivation) -> bool:
        """Supports SiLU, SwiGLU-OAI (uninterleaved), and RELU^2 non-gated."""
        return activation in [
            MoEActivation.SILU,
            MoEActivation.SWIGLUOAI_UNINTERLEAVE,
            MoEActivation.RELU2_NO_MUL,
        ]

    @staticmethod
    def _supports_parallel_config(moe_parallel_config: FusedMoEParallelConfig) -> bool:
        """Monolithic kernel so only use with naive DP/EP and TP."""
        return (
            not moe_parallel_config.use_all2all_kernels
            or moe_parallel_config.use_ag_rs_all2all_kernels
        ) and not (
            moe_parallel_config.enable_eplb or moe_parallel_config.is_sequence_parallel
        )


class TrtLlmFp8ExpertsModular(TrtLlmFp8ExpertsBase, mk.FusedMoEExpertsModular):
    """Fp8 TRTLLM-Gen MoE kernels. Supports modular interface."""

    @staticmethod
    def _supports_parallel_config(moe_parallel_config: FusedMoEParallelConfig) -> bool:
        return (
            not moe_parallel_config.use_all2all_kernels
            or moe_parallel_config.use_ag_rs_all2all_kernels
            or moe_parallel_config.use_deepep_v2_kernels
            or moe_parallel_config.use_fi_nvl_one_sided_kernels
            or moe_parallel_config.use_fi_nvl_two_sided_kernels
        ) and not moe_parallel_config.enable_eplb

    @staticmethod
    def _supports_quant_scheme(
        weight_key: QuantKey | None,
        activation_key: QuantKey | None,
    ) -> bool:
        """Supports Fp8 block and MXFP8."""
        SUPPORTED_W_A = [
            (kFp8Static128BlockSym, kFp8Dynamic128Sym),
            (kMxfp8Static, kMxfp8Dynamic),
        ]
        return (weight_key, activation_key) in SUPPORTED_W_A

    def moe_problem_size(
        self,
        a1: torch.Tensor,
        w1: torch.Tensor,
        w2: torch.Tensor,
        topk_ids: torch.Tensor,
    ) -> tuple[int, int, int, int, int]:
        """Override to handle 4D BlockMajorK weights (E, K/bk, Mn, bk)."""
        if w1.dim() == 4:
            # BlockMajorK: (E, K/bk, Mn, bk)
            E = w1.shape[0]
            N = w1.shape[2]
            K = a1.size(-1)
            M = a1.size(0) if a1.dim() == 2 else a1.size(1)
            topk = topk_ids.size(1)
            return E, M, N, K, topk
        return super().moe_problem_size(a1, w1, w2, topk_ids)

    def workspace_shapes(
        self,
        M: int,
        N: int,
        K: int,
        topk: int,
        global_num_experts: int,
        local_num_experts: int,
        expert_tokens_meta: mk.ExpertTokensMetadata | None,
        activation: MoEActivation,
    ) -> tuple[tuple[int, ...], tuple[int, ...], tuple[int, ...]]:
        # The workspaces for this implementation are managed by flashinfer.
        workspace1 = (0,)
        workspace2 = (0,)
        output = (M, K)

        return (workspace1, workspace2, output)

    def finalize_weight_and_reduce_impl(self) -> mk.TopKWeightAndReduce:
        return TopKWeightAndReduceNoOP()

    def apply(
        self,
        output: torch.Tensor,
        hidden_states: torch.Tensor,
        w1: torch.Tensor,
        w2: torch.Tensor,
        topk_weights: torch.Tensor,
        topk_ids: torch.Tensor,
        activation: MoEActivation,
        global_num_experts: int,
        expert_map: torch.Tensor | None,
        a1q_scale: torch.Tensor | None,
        a2_scale: torch.Tensor | None,
        workspace13: torch.Tensor,
        workspace2: torch.Tensor,
        expert_tokens_meta: mk.ExpertTokensMetadata | None,
        apply_router_weight_on_input: bool,
    ):
        import flashinfer
        from flashinfer.fused_moe import Fp8QuantizationType, WeightLayout

        topk_ids = topk_ids.to(dtype=torch.int32)

        if a1q_scale is None:
            raise RuntimeError(
                "TRT-LLM FP8 experts require precomputed activation scales"
            )
        assert a1q_scale is not None

        is_mxfp8 = self.quant_config.block_shape == [1, 32]
        if is_mxfp8:
            fp8_quant_type = Fp8QuantizationType.MxFp8
            use_shuffled_weight = True
            weight_layout = WeightLayout.MajorK
            hidden_states_scale = a1q_scale
        else:
            fp8_quant_type = Fp8QuantizationType.DeepSeekFp8
            use_shuffled_weight = True
            weight_layout = WeightLayout.BlockMajorK
            hidden_states_scale = prepare_deepseek_fp8_x_sf(hidden_states, a1q_scale)

        flashinfer.fused_moe.trtllm_fp8_block_scale_routed_moe(
            topk_ids=(topk_ids, topk_weights),
            routing_bias=None,
            hidden_states=hidden_states,
            hidden_states_scale=hidden_states_scale,
            gemm1_weights=w1,
            gemm1_weights_scale=self.quant_config.w1_scale,
            gemm1_alpha=self.gemm1_alpha,
            gemm1_beta=self.gemm1_beta,
            gemm1_clamp_limit=self.gemm1_clamp_limit,
            gemm2_weights=w2,
            gemm2_weights_scale=self.quant_config.w2_scale,
            num_experts=global_num_experts,
            top_k=topk_ids.size(1),
            n_group=None,
            topk_group=None,
            intermediate_size=self.intermediate_size_per_partition,
            local_expert_offset=self.ep_rank * self.local_num_experts,
            local_num_experts=self.local_num_experts,
            routed_scaling_factor=None,
            routing_method_type=1,  # not used
            use_shuffled_weight=use_shuffled_weight,
            weight_layout=weight_layout,
            fp8_quantization_type=fp8_quant_type,
            output=output,
            tune_max_num_tokens=fi_moe_largest_bucket(self.moe_config),
        )


class TrtLlmFp8ExpertsMonolithic(TrtLlmFp8ExpertsBase, mk.FusedMoEExpertsMonolithic):
    """Fp8 TRTLLM-Gen MoE kernels. Supports monolithic interface."""

    def supports_routing_replay_capture(self) -> bool:
        return True

    def supports_deferred_finalize(self) -> bool:
        # The MXFP8 path stops after GEMM2 when the config allows it.
        return self.quant_config.block_shape == [1, 32]

    def supports_fused_router_routing(self, gate: torch.nn.Module) -> bool:
        return (
            self.quant_config.block_shape == [1, 32]
            and self.moe_config.activation == MoEActivation.SILU
            and fused_router_routing_supported(
                gate=gate,
                routing_method=self.routing_method_type,
                num_experts=self.moe_config.num_experts,
                num_local_experts=self.local_num_experts,
                top_k=self.topk,
                hidden_size=self.hidden_dim,
                has_swiglu_params=self.gemm1_alpha is not None
                or self.gemm1_beta is not None
                or self.gemm1_clamp_limit is not None,
            )
        )

    def prepare_fused_router_routing(self, w1: torch.Tensor, w2: torch.Tensor) -> None:
        """Create the fused router + routing buffers before CUDA-graph capture
        (call only when ``supports_fused_router_routing`` holds).
        """
        prepare_fused_router_routing(
            self,
            w1,
            w2,
            activation_type=activation_to_flashinfer_int(self.moe_config.activation),
        )

    def __init__(
        self,
        moe_config: FusedMoEConfig,
        quant_config: FusedMoEQuantConfig,
    ):
        super().__init__(moe_config, quant_config)

        # Make additional scales for per-tensor interface.
        if self.quant_config.is_per_tensor:
            w1_scale = self.quant_config.w1_scale
            assert w1_scale is not None
            a1_scale = self.quant_config.a1_scale
            assert a1_scale is not None
            w2_scale = self.quant_config.w2_scale
            assert w2_scale is not None
            a2_scale = self.quant_config.a2_scale
            assert a2_scale is not None

            self._g1_alphas = (w1_scale * a1_scale).squeeze()
            self._g2_alphas = (w2_scale * a2_scale).squeeze()
            self._g1_scale_c = (
                self._g1_alphas / self.quant_config.a2_scale
                if moe_config.is_act_and_mul
                else torch.ones_like(self._g1_alphas) / self.quant_config.a2_scale
            )

    @staticmethod
    def _supports_quant_scheme(
        weight_key: QuantKey | None,
        activation_key: QuantKey | None,
    ) -> bool:
        """Supports Fp8 per-tensor, Fp8 block, and MXFP8."""
        SUPPORTED_W_A = [
            (kFp8Static128BlockSym, kFp8Dynamic128Sym),
            (kFp8StaticTensorSym, kFp8StaticTensorSym),
            (kMxfp8Static, kMxfp8Dynamic),
        ]
        return (weight_key, activation_key) in SUPPORTED_W_A

    @staticmethod
    def _supports_router_logits_dtype(
        router_logits_dtype: torch.dtype | None,
        routing_method: RoutingMethodType,
    ) -> bool:
        return router_logits_dtype in [torch.bfloat16, torch.float32]

    @staticmethod
    def _supports_routing_method(
        routing_method: RoutingMethodType,
        weight_key: QuantKey | None,
        activation_key: QuantKey | None,
    ) -> bool:
        """Monolithic kernels need to express router support."""
        # NOTE(dbari): TopK routing could also be enabled, but need to validate models
        # NOTE(dbari): Default is not implemented and should not be enabled until it is

        if (weight_key, activation_key) in [
            (kFp8Static128BlockSym, kFp8Dynamic128Sym),
            (kMxfp8Static, kMxfp8Dynamic),
        ]:
            # NOTE(rob): potentially allow others here. This is a conservative list.
            return routing_method in [
                RoutingMethodType.DeepSeekV3,
                RoutingMethodType.Renormalize,
                RoutingMethodType.RenormalizeNaive,
                RoutingMethodType.SigmoidRenorm,
                RoutingMethodType.Sigmoid,
                RoutingMethodType.MiniMax2,
                RoutingMethodType.Simulated,
            ]
        elif (weight_key, activation_key) == (kFp8StaticTensorSym, kFp8StaticTensorSym):
            # NOTE(dbari): as above, potentially allow others here.
            return routing_method in [
                RoutingMethodType.DeepSeekV3,
                RoutingMethodType.Llama4,
                RoutingMethodType.Renormalize,
                RoutingMethodType.RenormalizeNaive,
                RoutingMethodType.SigmoidRenorm,
                RoutingMethodType.Sigmoid,
                RoutingMethodType.MiniMax2,
                RoutingMethodType.Simulated,
            ]
        else:
            raise ValueError("Unsupported quantization scheme.")

    def _apply_block_scale(
        self,
        hidden_states: torch.Tensor,
        w1: torch.Tensor,
        w2: torch.Tensor,
        router_logits: torch.Tensor,
        activation: MoEActivation,
        global_num_experts: int,
        expert_map: torch.Tensor | None,
        a1q_scale: torch.Tensor | None,
        apply_router_weight_on_input: bool,
        # grouped topk + fused topk bias parameters
        num_expert_group: int | None = None,
        e_score_correction_bias: torch.Tensor | None = None,
        routed_scaling_factor: float | None = None,
        topk_group: int | None = None,
    ) -> torch.Tensor | UnfinalizedMoEOutput:
        import flashinfer
        from flashinfer.fused_moe import Fp8QuantizationType, WeightLayout

        assert not apply_router_weight_on_input
        assert activation in [
            MoEActivation.SILU,
            MoEActivation.SWIGLUOAI_UNINTERLEAVE,
            MoEActivation.RELU2_NO_MUL,
        ]
        activation_type = activation_to_flashinfer_int(activation)
        assert self.topk <= global_num_experts
        assert global_num_experts % 4 == 0
        assert self.quant_config.block_shape in [[128, 128], [1, 32]]
        # Kernel expects #experts <= #threads 512
        assert global_num_experts <= 512
        # TODO: fuse into the quant kernel.
        assert a1q_scale is not None

        is_mxfp8 = self.quant_config.block_shape == [1, 32]
        if is_mxfp8:
            fp8_quant_type = Fp8QuantizationType.MxFp8
            use_shuffled_weight = True
            weight_layout = WeightLayout.MajorK
            hidden_states_scale = a1q_scale
            # FlashInfer expects None for non-grouped MXFP8 routing configs.
            n_group = num_expert_group or None
            selected_topk_group = topk_group or None
        else:
            assert self.topk <= 32
            fp8_quant_type = Fp8QuantizationType.DeepSeekFp8
            use_shuffled_weight = True
            weight_layout = WeightLayout.BlockMajorK
            hidden_states_scale = a1q_scale.t().contiguous()
            n_group = num_expert_group or 0
            selected_topk_group = topk_group or 0

        num_tokens = hidden_states.shape[0]
        # FlashInfer's 0-token call keeps the finalized (empty) form.
        defer = is_mxfp8 and self.moe_config.should_defer_moe_finalize(num_tokens)
        if isinstance(router_logits, FusedRouterInput):
            result = None
            if (
                is_mxfp8
                and e_score_correction_bias is None
                and routed_scaling_factor in (None, 1.0)
                and n_group is None
                and selected_topk_group is None
            ):
                result = run_fused_router_routing(
                    self,
                    router_logits,
                    hidden_states,
                    hidden_states_scale,
                    w1,
                    w2,
                    activation_type=activation_type,
                    deferred=defer,
                    # The fused kernel and the bmm FC1/FC2 wait on their
                    # producer before reading it, as the gated stock chain.
                    use_pdl=current_platform.is_device_capability(107)
                    and _sm107_moe_pdl_allowed(
                        num_tokens,
                        global_num_experts,
                        hidden_states.shape[-1],
                        self.routing_method_type,
                        n_group,
                        self.topk,
                        deferred=defer,
                    ),
                )
            if result is not None:
                return result
            router_logits = router_logits.logits()

        routing_replay_out = self._maybe_make_routing_replay_buffer(
            num_tokens=num_tokens,
            device=hidden_states.device,
        )
        kwargs = dict(
            routing_logits=router_logits,
            routing_bias=e_score_correction_bias,
            hidden_states=hidden_states,
            hidden_states_scale=hidden_states_scale,
            gemm1_weights=w1,
            gemm1_weights_scale=self.quant_config.w1_scale,
            gemm1_alpha=self.gemm1_alpha,
            gemm1_beta=self.gemm1_beta,
            gemm1_clamp_limit=self.gemm1_clamp_limit,
            gemm2_weights=w2,
            gemm2_weights_scale=self.quant_config.w2_scale,
            num_experts=global_num_experts,
            top_k=self.topk,
            n_group=n_group,
            topk_group=selected_topk_group,
            intermediate_size=self.intermediate_size_per_partition,
            local_expert_offset=self.ep_rank * self.local_num_experts,
            local_num_experts=self.local_num_experts,
            routed_scaling_factor=routed_scaling_factor,
            routing_method_type=self.routing_method_type,
            use_shuffled_weight=use_shuffled_weight,
            weight_layout=weight_layout,
            fp8_quantization_type=fp8_quant_type,
            routing_replay_out=routing_replay_out,
            tune_max_num_tokens=fi_moe_largest_bucket(self.moe_config),
        )
        if is_mxfp8 or activation == MoEActivation.RELU2_NO_MUL:
            kwargs["activation_type"] = activation_type
        if defer:
            kwargs["do_finalize"] = False
        with _sm107_moe_pdl(
            num_tokens,
            global_num_experts,
            hidden_states.shape[-1],
            self.routing_method_type,
            n_group,
            self.topk,
            deferred=defer,
        ):
            result = flashinfer.fused_moe.trtllm_fp8_block_scale_moe(**kwargs)
        self._maybe_dispatch_routing_replay(routing_replay_out, num_tokens=num_tokens)
        if defer:
            return convert_flashinfer_moe_output(
                result, do_finalize=False, num_tokens=num_tokens, top_k=self.topk
            )
        return result

    def _apply_per_tensor(
        self,
        hidden_states: torch.Tensor,
        w1: torch.Tensor,
        w2: torch.Tensor,
        router_logits: torch.Tensor,
        activation: MoEActivation,
        global_num_experts: int,
        expert_map: torch.Tensor | None,
        a1q_scale: torch.Tensor | None,
        apply_router_weight_on_input: bool,
        # grouped topk + fused topk bias parameters
        num_expert_group: int | None = None,
        e_score_correction_bias: torch.Tensor | None = None,
        routed_scaling_factor: float | None = None,
        topk_group: int | None = None,
    ) -> torch.Tensor:
        # Delay import for non-CUDA.
        import flashinfer

        # Confirm supported activation function.
        assert activation in [MoEActivation.SILU, MoEActivation.RELU2_NO_MUL]

        activation_type = activation_to_flashinfer_int(activation)

        # Confirm Llama-4 routing is proper.
        if self.routing_method_type == RoutingMethodType.Llama4:
            assert apply_router_weight_on_input
        else:
            assert not apply_router_weight_on_input

        routing_replay_out = self._maybe_make_routing_replay_buffer(
            num_tokens=hidden_states.shape[0],
            device=hidden_states.device,
        )

        out = flashinfer.fused_moe.trtllm_fp8_per_tensor_scale_moe(
            routing_logits=router_logits,
            routing_bias=e_score_correction_bias,
            hidden_states=hidden_states,
            gemm1_weights=w1,
            output1_scales_scalar=self._g1_scale_c,
            output1_scales_gate_scalar=self._g1_alphas,
            gemm2_weights=w2,
            output2_scales_scalar=self._g2_alphas,
            num_experts=global_num_experts,
            top_k=self.topk,
            n_group=num_expert_group or 0,
            topk_group=topk_group or 0,
            intermediate_size=self.intermediate_size_per_partition,
            local_expert_offset=self.ep_rank * self.local_num_experts,
            local_num_experts=self.local_num_experts,
            routed_scaling_factor=routed_scaling_factor,
            use_routing_scales_on_input=apply_router_weight_on_input,
            routing_method_type=self.routing_method_type,
            activation_type=activation_type,
            tune_max_num_tokens=fi_moe_largest_bucket(self.moe_config),
            routing_replay_out=routing_replay_out,
        )
        self._maybe_dispatch_routing_replay(
            routing_replay_out, num_tokens=hidden_states.shape[0]
        )
        return out

    def apply(
        self,
        hidden_states: torch.Tensor,
        w1: torch.Tensor,
        w2: torch.Tensor,
        router_logits: torch.Tensor,
        activation: MoEActivation,
        global_num_experts: int,
        expert_map: torch.Tensor | None,
        a1q_scale: torch.Tensor | None,
        apply_router_weight_on_input: bool,
        # grouped topk + fused topk bias parameters
        num_expert_group: int | None = None,
        e_score_correction_bias: torch.Tensor | None = None,
        routed_scaling_factor: float | None = None,
        topk_group: int | None = None,
    ) -> torch.Tensor | UnfinalizedMoEOutput:
        if self.quant_config.block_shape is not None:
            return self._apply_block_scale(
                hidden_states,
                w1,
                w2,
                router_logits,
                activation,
                global_num_experts,
                expert_map,
                a1q_scale,
                apply_router_weight_on_input,
                num_expert_group=num_expert_group,
                e_score_correction_bias=e_score_correction_bias,
                routed_scaling_factor=routed_scaling_factor,
                topk_group=topk_group,
            )
        elif self.quant_config.is_per_tensor:
            return self._apply_per_tensor(
                hidden_states,
                w1,
                w2,
                router_logits,
                activation,
                global_num_experts,
                expert_map,
                a1q_scale,
                apply_router_weight_on_input,
                num_expert_group=num_expert_group,
                e_score_correction_bias=e_score_correction_bias,
                routed_scaling_factor=routed_scaling_factor,
            )
        else:
            raise NotImplementedError(
                "Only per-block, per-tensor, and MXFP8 quantization are "
                f"supported in {self.__class__.__name__}."
            )
