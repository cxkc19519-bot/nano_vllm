from dataclasses import dataclass
import torch


@dataclass(slots=True)
class Context:
    is_prefill: bool = False
    cu_seqlens_q: torch.Tensor | None = None
    cu_seqlens_k: torch.Tensor | None = None
    max_seqlen_q: int = 0
    max_seqlen_k: int = 0
    slot_mapping: torch.Tensor | None = None
    context_lens: torch.Tensor | None = None
    block_tables: torch.Tensor | None = None
    seqs: list | None = None
    # One stable DeltaNet state slot per sequence in the current batch.  Unlike
    # KV slots, these identify a complete recurrent/conv state for every linear
    # attention layer.
    state_slot_mapping: torch.Tensor | None = None
    # Slots which must be cleared before this invocation (new request or a
    # request rebuilt after preemption).
    state_reset_slots: torch.Tensor | None = None

_CONTEXT = Context()

def get_context():
    return _CONTEXT

def set_context(is_prefill, cu_seqlens_q=None, cu_seqlens_k=None, max_seqlen_q=0, max_seqlen_k=0, slot_mapping=None, context_lens=None, block_tables=None, seqs=None, state_slot_mapping=None, state_reset_slots=None):
    global _CONTEXT
    _CONTEXT = Context(
        is_prefill, cu_seqlens_q, cu_seqlens_k, max_seqlen_q, max_seqlen_k,
        slot_mapping, context_lens, block_tables, seqs, state_slot_mapping,
        state_reset_slots,
    )

def reset_context():
    global _CONTEXT
    _CONTEXT = Context()
