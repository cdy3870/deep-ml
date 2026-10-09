def kv_cache_bytes(batch: int, seqlen: int, n_layers: int, n_heads: int, head_dim: int, n_kv_groups: int, latent_dim: int, attn_type: str, bytes_per_elem: int = 2) -> int:
    """Return KV cache memory in bytes for the given attention type."""
    

    # multi-head attention
    mha_bytes = 2 * batch * seqlen * n_layers * n_heads * head_dim * bytes_per_elem

    # grouped-query attention
    gqa_bytes = 2 * batch * seqlen * n_layers * n_kv_groups * head_dim * bytes_per_elem

    # multi-head latent attention
    mla_bytes = batch * seqlen * n_layers * latent_dim * bytes_per_elem

    if attn_type == "mha":
        return mha_bytes
    elif attn_type == "gqa":
        return gqa_bytes
    
    return mla_bytes
