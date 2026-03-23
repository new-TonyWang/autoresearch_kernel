import torch


def get_inputs(
    axes_and_scalars: dict[str, ...], device: torch.device
) -> dict[str, torch.Tensor]:
    """Generate inputs for backward pass testing."""
    batch_size = axes_and_scalars["batch_size"]
    seq_len_q = axes_and_scalars["seq_len_q"]
    seq_len_kv = axes_and_scalars["seq_len_kv"]
    num_attention_heads = 80
    num_key_value_heads = 8
    head_dim = 128
    # Use a fixed dropout probability for testing
    attention_dropout = 0.1
    
    # Gradient of attention output
    grad_attn_output = torch.randn(
        batch_size, seq_len_q, num_attention_heads, head_dim,
        dtype=torch.bfloat16, device=device
    )
    
    # Attention weights after softmax (should sum to 1 along last dim)
    attn_scores_raw = torch.randn(
        batch_size, num_attention_heads, seq_len_q, seq_len_kv,
        dtype=torch.float32, device=device
    )
    attn_weights = torch.softmax(attn_scores_raw, dim=-1).to(torch.bfloat16)
    
    # Generate dropout mask
    dropout_mask = torch.rand(
        batch_size, num_attention_heads, seq_len_q, seq_len_kv,
        device=device
    ) > attention_dropout
    
    # Attention weights after dropout
    if attention_dropout > 0.0:
        attn_weights_dropped = (attn_weights.float() * dropout_mask / (1.0 - attention_dropout)).to(torch.bfloat16)
    else:
        attn_weights_dropped = attn_weights
    
    # Value states
    value_states = torch.randn(
        batch_size, num_key_value_heads, seq_len_kv, head_dim,
        dtype=torch.bfloat16, device=device
    )
    
    return {
        "grad_attn_output": grad_attn_output,
        "attn_weights": attn_weights,
        "attn_weights_dropped": attn_weights_dropped,
        "value_states": value_states,
        "dropout_mask": dropout_mask,
        "attention_dropout": attention_dropout,
    }
