import torch
import torch.distributed as dist

# rearrange lives in einops (an existing OpenRLHF dependency); flash_attn only re-exported it.
from einops import rearrange

# Prefer the external flash_attn implementations when the package is installed and usable
# (the established NVIDIA/CUDA path, kept unchanged). Fall back to backend-neutral equivalents
# ONLY when the top-level flash_attn package is absent - e.g. Intel XPU environments where the
# flash_attn package is not available. We match exc.name exactly against "flash_attn": a
# flash_attn that is installed-but-broken raises ModuleNotFoundError for one of its OWN
# submodules (e.g. "flash_attn_2_cuda" when the compiled extension is missing, or
# "flash_attn.bert_padding" on a version/layout mismatch), and those must surface as real
# errors rather than silently activating the fallback.
try:
    from flash_attn.bert_padding import index_first_axis, pad_input, unpad_input
    from flash_attn.utils.distributed import all_gather
except ModuleNotFoundError as exc:
    if exc.name != "flash_attn":
        raise

    # transformers ships PyTorch implementations of the padding helpers. They are private
    # (underscore-prefixed) APIs, so tests/test_ring_attn_utils.py guards their expected
    # signatures/behavior against transformers upgrades.
    #
    # _pad_input / _unpad_input match flash_attn's pad_input / unpad_input contracts and are
    # aliased directly. _index_first_axis is NOT aliased: transformers' version assumes a
    # (batch, seqlen, ...) input and flattens the first two dims before indexing, whereas
    # flash_attn's index_first_axis selects rows along axis 0 and preserves all trailing dims.
    # OpenRLHF calls index_first_axis on an already-flattened (batch*seqlen, 1) tensor and then
    # transposes, which needs the trailing dim to survive - so we provide a flash_attn-compatible
    # wrapper below instead. (Discovered via a real GRPO --packing_samples run, not unit tests.)
    from transformers.modeling_flash_attention_utils import _pad_input as pad_input
    from transformers.modeling_flash_attention_utils import _unpad_input as unpad_input

    def index_first_axis(tensor, indices):
        """Select rows along axis 0 while preserving all trailing dimensions.

        Preserves the contract of flash_attn.bert_padding.index_first_axis:
        (total, ...) -> (len(indices), ...). Pure torch, no CUDA-specific code; the
        gather is autograd-aware so gradients flow back to the selected rows.
        """
        return torch.index_select(tensor, 0, indices)

    class _AllGatherFunc(torch.autograd.Function):
        """Autograd-aware all-gather fallback for flash_attn.utils.distributed.all_gather.

        transformers ships no replacement for this one, so it is vendored here. Pure
        torch.distributed, no CUDA-specific code. Forward all-gathers along dim 0 across ranks;
        backward reduce-scatters so each rank receives the gradient for its original shard -
        the same autograd relationship as flash_attn's version.
        """

        @staticmethod
        def forward(ctx, input_, process_group):
            ctx.process_group = process_group
            if not dist.is_initialized():
                raise RuntimeError("torch.distributed must be initialized before all_gather")
            world_size = dist.get_world_size(process_group)
            input_ = input_.contiguous()
            output = torch.empty(
                world_size * input_.shape[0], *input_.shape[1:], dtype=input_.dtype, device=input_.device
            )
            dist.all_gather_into_tensor(output, input_, group=process_group)
            return output

        @staticmethod
        def backward(ctx, grad_output):
            world_size = dist.get_world_size(ctx.process_group)
            if grad_output.shape[0] % world_size != 0:
                raise RuntimeError(
                    f"grad_output dim 0 must be divisible by world size {world_size}; got {grad_output.shape[0]}"
                )
            grad_output = grad_output.contiguous()
            grad_input = torch.empty(
                grad_output.shape[0] // world_size,
                *grad_output.shape[1:],
                dtype=grad_output.dtype,
                device=grad_output.device,
            )
            dist.reduce_scatter_tensor(grad_input, grad_output, group=ctx.process_group)
            return grad_input, None

    all_gather = _AllGatherFunc.apply


RING_ATTN_GROUP = None


def patch_transformers_for_ring_flash_attn():
    """ring_flash_attn<=0.1.8 imports is_flash_attn_greater_or_equal_2_10 from
    transformers.modeling_flash_attention_utils, but transformers>=5.5.4 moved
    it to transformers.utils. Re-export the symbol so the import keeps working.
    See https://github.com/OpenRLHF/OpenRLHF/issues/1222.
    """
    import transformers.modeling_flash_attention_utils as _m

    if not hasattr(_m, "is_flash_attn_greater_or_equal_2_10"):
        from transformers.utils import is_flash_attn_greater_or_equal_2_10

        _m.is_flash_attn_greater_or_equal_2_10 = is_flash_attn_greater_or_equal_2_10


def set_ring_attn_group(group):
    global RING_ATTN_GROUP
    RING_ATTN_GROUP = group


def get_ring_attn_group():
    return RING_ATTN_GROUP


def reset_ring_attn_position_ids(start, end, packed_seq_lens):
    """
    Calculate position ids for packed_seq_ids[start:end].
    For example, if the packed_seq_lens is [3, 2, 4, 1], start=2, end=8,
    the position ids will be [2, 0, 1, 0, 1, 2].

    Args:
        start: the start position
        end: the end position
        packed_seq_lens: the sequence lengths of packed sequences
    """
    position_ids = torch.zeros((1, end - start), dtype=torch.long, device=torch.accelerator.current_device_index())
    offset = 0
    for seqlen in packed_seq_lens:
        seq_start = max(offset, start)
        seq_end = min(offset + seqlen, end)
        if seq_start < seq_end:
            position_ids[0, seq_start - start : seq_end - start] = torch.arange(seq_start - offset, seq_end - offset)

        offset += seqlen
        if offset >= end:
            break
    return position_ids


def update_ring_attn_params(cu_seqlens):
    """
    Calculate the cu_seqlens for the current forward pass and pass the value to
    the substituted ring_flash_attn.

    Note that total_seq_len may be larger than the sum of packed_seq_lens because of padding.
    """
    assert RING_ATTN_GROUP is not None

    patch_transformers_for_ring_flash_attn()
    from ring_flash_attn import update_ring_flash_attn_params

    update_ring_flash_attn_params(cu_seqlens, RING_ATTN_GROUP)


def get_tensor_in_current_ring_attn_rank(tensors: list[torch.Tensor] | torch.Tensor, ring_attn_group, pad_id):
    """
    Deal with padding and slice the tensor to current ring_attn_rank.
    Args:
        tensors: Each tensor shaped (batch, seqlen) or (1, total_seqs)
        ring_attn_group: Ring attention group
        pad_id: Padding id
    Returns:
        Processed tensor
    """
    if isinstance(tensors, torch.Tensor):
        tensors = [tensors]
    ring_attn_rank = dist.get_rank(group=ring_attn_group)
    ring_attn_size = dist.get_world_size(group=ring_attn_group)
    seqlen = tensors[0].shape[-1]
    total_seq_len = tensors[0].numel()
    ring_attn_pad_len = (ring_attn_size - seqlen % ring_attn_size) % ring_attn_size
    output_tensors = []
    for tensor in tensors:
        if tensor.numel() != total_seq_len:
            raise ValueError(f"tensor.numel() {tensor.numel()} != total_seq_len {total_seq_len}")
        tensor = torch.nn.functional.pad(tensor, (0, ring_attn_pad_len), value=pad_id)
        local_seq_len = tensor.numel() // ring_attn_size
        start, end = ring_attn_rank * local_seq_len, (ring_attn_rank + 1) * local_seq_len
        tensor = tensor[:, start:end]
        output_tensors.append(tensor)
    if len(output_tensors) == 1:
        output_tensors = output_tensors[0]
    return output_tensors, ring_attn_pad_len


def unpad_and_slice_tensor(sequences, attention_mask, ring_attn_group):
    """
    Unpad and slice tensor for distributed training with ring attention.

    This function performs several operations:
    1. Removes padding, unpads sequences from (batch, seqlen) to (1, total_seqs)
    2. Adapts to ring_attn_group, pads sequences to be divisible by ring_attn_group
    3. Slices the sequences for the current ring_attn_rank

    Example:
        >>> # Input sequences shape: (batch=2, seqlen=4)
        >>> sequences = [[1, 2, 3, 0], [4, 5, 0, 0]]  # 0 is padding
        >>> attention_mask = [[1, 1, 1, 0], [1, 1, 0, 0]]
        >>> # After unpad:
        >>> # sequences: [1, 2, 3, 4, 5]  # shape (1, total_seqs=5)
        >>> # If ring_attn_group size is 2, it will pad to length 6
        >>> # Then slice for current rank (e.g., rank 0 gets [1,2,3], rank 1 gets [4,5,0])

    Args:
        sequences: Input sequences tensor of shape (batch, seqlen)
        attention_mask: Attention mask tensor for the sequences
        ring_attn_group: Ring attention group for distributed processing

    Returns:
        tuple: Processed sequences and related tensors for ring attention
    """
    rolled_sequences = torch.roll(sequences, shifts=-1, dims=1)
    sequences, indices, cu_seqlens, _, _ = unpad_input(sequences.unsqueeze(-1), attention_mask)
    sequences = sequences.transpose(0, 1)  # (1, total_seqs)
    rolled_sequences = index_first_axis(
        rearrange(rolled_sequences.unsqueeze(-1), "b s ... -> (b s) ..."), indices
    ).transpose(
        0, 1
    )  # (1, total_seqs)
    position_ids = torch.clip(torch.cumsum(attention_mask, dim=-1) - 1, min=0, max=None)
    position_ids = index_first_axis(rearrange(position_ids.unsqueeze(-1), "b s ... -> (b s) ..."), indices).transpose(
        0, 1
    )  # (1, total_seqs)
    ring_attn_pad_len = 0
    if ring_attn_group is not None:
        (sequences, position_ids, rolled_sequences), ring_attn_pad_len = get_tensor_in_current_ring_attn_rank(
            [sequences, position_ids, rolled_sequences], ring_attn_group, 0
        )
        cu_seqlens[-1] += ring_attn_pad_len
        update_ring_attn_params(cu_seqlens)
    return sequences, position_ids, rolled_sequences, ring_attn_pad_len, indices


def gather_and_pad_tensor(tensor, ring_attn_group, ring_attn_pad_len, indices, batch, seqlen):
    """
    Gather and pad tensor data (such as logits, log_probs, etc.).

    Example:
        >>> # Input tensor from each rank (shape: (1, local_seq_len))
        >>> # Rank 0: [1, 2, 3]
        >>> # Rank 1: [4, 5, 0]  # 0 is padding
        >>> # After all_gather:
        >>> # tensor: [1, 2, 3, 4, 5, 0]  # shape (1, total_seqs=6)
        >>> # After removing padding (ring_attn_pad_len=1):
        >>> # tensor: [1, 2, 3, 4, 5]  # shape (1, total_seqs=5)
        >>> # After pad_input with original indices:
        >>> # tensor: [[1, 2, 3, 0], [4, 5, 0, 0]]  # shape (batch=2, seqlen=4)

    Args:
        tensor: Input tensor, can be logits, log_probs, etc.
        ring_attn_group: Ring attention group
        ring_attn_pad_len: Padding length
        indices: Indices
        batch: Batch size
        seqlen: Sequence length

    Returns:
        Padded tensor
    """
    if ring_attn_group is not None:
        tensor = all_gather(tensor.transpose(0, 1), ring_attn_group).transpose(0, 1)  # (1, total_seqs)
        if ring_attn_pad_len > 0:
            tensor = tensor[:, :-ring_attn_pad_len]
    tensor = pad_input(tensor.transpose(0, 1), indices, batch, seqlen).squeeze(-1)  # (batch, seqlen)
    return tensor
