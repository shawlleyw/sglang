import torch
import torch.distributed as dist
from typing import Optional

from sglang.srt.distributed.parallel_state import (
    get_world_group,
    init_model_parallel_group,
    get_bool_env_var,
    GroupCoordinator,
)
import sglang.srt.distributed.parallel_state as parallel_state
import sglang.srt.layers.dp_attention as dp_attention

_PARAS_EP: Optional[GroupCoordinator] = None

_PARAS_TP: Optional[GroupCoordinator] = None

_PARAS_SELF: Optional[GroupCoordinator] = None

def get_paras_tp_group() -> GroupCoordinator:
    assert _PARAS_TP is not None, "ParaS tensor parallel group is not initialized"
    return _PARAS_TP

# TODO(shaoyuw): refactor code
# The parallel size and rank can be grouped together.
# There are 2 stages to consider:
# stage 1. EP 
# stage 2. 2D parallel (DTP?)

_PARAS_TP_SIZE: int = None
_PARAS_TP_RANK: int = None
_PARAS_DP_SIZE: int = None
_PARAS_DP_RANK: int = None
_PARAS_EP_SIZE: int = None
_PARAS_EP_RANK: int = None


def initialize_paras_parallel(
    dp_size: int = 1,
    tp_size: int = 1,
    global_rank: int = 0,
    backend: Optional[str] = None,
) -> None:
    """
    Initialize ParaS parallel groups.

    Arguments:
        dp_size: number of GPUs used for data parallelism.
        tp_size: number of GPUs used for tensor parallelism.
    """

    # Get world size and rank. Ensure some consistencies.
    assert torch.distributed.is_initialized()
    world_size: int = torch.distributed.get_world_size()
    backend = backend or torch.distributed.get_backend(get_world_group().device_group)

    if world_size != dp_size * tp_size:
        raise RuntimeError(
            f"ParaS: world_size ({world_size}) is not equal to "
            f"dp_size ({dp_size}) x tp_size ({tp_size})"
        )

    # get paras parallel size and rank
    # Since paras is launched with EP mode, _MOE_TP is set to self rank
    global _PARAS_EP, _PARAS_TP, _PARAS_SELF
    _PARAS_EP = parallel_state._MOE_EP
    _PARAS_SELF = parallel_state._MOE_TP
    assert _PARAS_SELF.world_size == 1, f"ParaS self group world size is not 1, got {_PARAS_SELF.world_size}"

    global _PARAS_TP_SIZE, _PARAS_DP_SIZE, _PARAS_EP_SIZE, _PARAS_TP_RANK, _PARAS_DP_RANK, _PARAS_EP_RANK
    _PARAS_TP_SIZE = tp_size
    _PARAS_DP_SIZE = dp_size
    _PARAS_EP_SIZE = dp_size * tp_size

    _PARAS_TP_RANK = global_rank % tp_size
    _PARAS_DP_RANK = global_rank // tp_size
    _PARAS_EP_RANK = global_rank

    # Build the ParaS tensor model-parallel groups.
    #
    # Memory optimization: when the paras_tp group ranks are identical to an
    # existing group's ranks, alias the existing group instead of creating a new
    # torch.distributed ProcessGroup + NCCL communicator. This saves one full
    # NCCL communicator per ParaS group (ncclCommInitRank, channel buffers,
    # per-comm NCCL scratch) and avoids the warmup collective.
    #
    # Default config (--tp-size 4 --dp-size 1 --ep-size 4, world_size=4):
    #   paras_tp ranks == _TP ranks (all world ranks) → alias to _TP.
    #   paras_dp ranks == _MOE_TP ranks (singletons)   → alias to _MOE_TP.
    num_paras_tensor_model_parallel_groups: int = world_size // tp_size
    assert _PARAS_TP is None, "ParaS tensor parallel group is already initialized"

    # paras_tp: alias _TP when ranks match exactly
    if tp_size == world_size:
        _PARAS_TP = parallel_state._TP
    else:
        group_ranks = []
        for i in range(num_paras_tensor_model_parallel_groups):
            ranks = list(range(i * tp_size, (i + 1) * tp_size))
            group_ranks.append(ranks)

        _PARAS_TP = init_model_parallel_group(
            group_ranks,
            get_world_group().local_rank,
            backend,
            use_message_queue_broadcaster=get_bool_env_var(
                "SGLANG_USE_MESSAGE_QUEUE_BROADCASTER", "true"
            ),
            group_name="paras_tp",
        )
        # Warmup only for freshly-created groups: the aliased _TP has already
        # been warmed up by sglang's normal init.
        x = torch.ones(128 * _PARAS_TP_SIZE, dtype=torch.bfloat16, device=_PARAS_TP.device)
        scattered_x = torch.empty_like(x)
        dist.all_to_all_single(scattered_x, x, group=_PARAS_TP.device_group)

    # The paras_dp NCCL communicator was removed: the fused dptp peer-access
    # scatter (kernels_dptp.cu) replaced the all-gather over dp ranks.
    # Scalar dp_size / dp_rank are still derived above for kernel parameters.

def get_paras_tp_size() -> int:
    assert _PARAS_TP_SIZE is not None, "ParaS tensor parallel size is not initialized"
    return _PARAS_TP_SIZE

def get_paras_tp_rank() -> int:
    assert _PARAS_TP_RANK is not None, "ParaS tensor parallel rank is not initialized"
    return _PARAS_TP_RANK

def get_paras_dp_size() -> int:
    assert _PARAS_DP_SIZE is not None, "ParaS data parallel size is not initialized"
    return _PARAS_DP_SIZE

def get_paras_dp_rank() -> int:
    assert _PARAS_DP_RANK is not None, "ParaS data parallel rank is not initialized"
    return _PARAS_DP_RANK

def get_paras_ep_group() -> GroupCoordinator:
    assert _PARAS_EP is not None, "ParaS expert parallel group is not initialized"
    return _PARAS_EP

def get_paras_ep_size() -> int:
    assert _PARAS_EP_SIZE is not None, "ParaS expert parallel size is not initialized"
    return _PARAS_EP_SIZE

def get_paras_ep_rank() -> int:
    assert _PARAS_EP_RANK is not None, "ParaS expert parallel rank is not initialized"
    return _PARAS_EP_RANK

def paras_comm_configure_tp():
    # global _TP
    parallel_state._TP = _PARAS_TP
    parallel_state._MOE_EP = _PARAS_SELF
    parallel_state._MOE_TP = _PARAS_TP

    # global _ATTN_TP_RANK, _ATTN_TP_SIZE, _ATTN_DP_RANK, _ATTN_DP_SIZE
    dp_attention._ATTN_TP_RANK = _PARAS_TP_RANK
    dp_attention._ATTN_TP_SIZE = _PARAS_TP_SIZE
    dp_attention._ATTN_DP_RANK = 0
    dp_attention._ATTN_DP_SIZE = 1

    # global _LOCAL_ATTN_DP_RANK, _LOCAL_ATTN_DP_SIZE
    dp_attention._LOCAL_ATTN_DP_SIZE = 1
    dp_attention._LOCAL_ATTN_DP_RANK = 0

def paras_comm_configure_ep():
    # TODO(shaoyuw): adapt for moe dense tp
    # global _TP
    parallel_state._TP = _PARAS_EP
    parallel_state._MOE_EP = _PARAS_EP
    parallel_state._MOE_TP = _PARAS_SELF

    # global _ATTN_TP_RANK, _ATTN_TP_SIZE, _ATTN_DP_RANK, _ATTN_DP_SIZE
    dp_attention._ATTN_TP_RANK = 0
    dp_attention._ATTN_TP_SIZE = 1
    dp_attention._ATTN_DP_RANK = _PARAS_EP_RANK
    dp_attention._ATTN_DP_SIZE = _PARAS_EP_SIZE

    # global _LOCAL_ATTN_DP_RANK, _LOCAL_ATTN_DP_SIZE
    dp_attention._LOCAL_ATTN_DP_SIZE = _PARAS_EP_SIZE
    dp_attention._LOCAL_ATTN_DP_RANK = _PARAS_EP_RANK
