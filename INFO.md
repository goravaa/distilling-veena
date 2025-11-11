--- Generating Hindi ---
[kavya] Generation: 52.17s | Decode: 1.71s | Total: 53.88s | GPU: T4

--- Generating English ---
[agastya] Generation: 39.88s | Decode: 0.04s | Total: 39.92s | GPU: T4

--- Generating Code-Mixed ---
[maitri] Generation: 35.25s | Decode: 0.04s | Total: 35.28s | GPU: T4


LlamaForCausalLM(
  (model): LlamaModel(
    (embed_tokens): Embedding(156951, 3072)
    (layers): ModuleList(
      (0-27): 28 x LlamaDecoderLayer(
        (self_attn): LlamaAttention(
          (q_proj): Linear4bit(in_features=3072, out_features=3072, bias=False)
          (k_proj): Linear4bit(in_features=3072, out_features=1024, bias=False)
          (v_proj): Linear4bit(in_features=3072, out_features=1024, bias=False)
          (o_proj): Linear4bit(in_features=3072, out_features=3072, bias=False)
        )
        (mlp): LlamaMLP(
          (gate_proj): Linear4bit(in_features=3072, out_features=8192, bias=False)
          (up_proj): Linear4bit(in_features=3072, out_features=8192, bias=False)
          (down_proj): Linear4bit(in_features=8192, out_features=3072, bias=False)
          (act_fn): SiLUActivation()
        )
        (input_layernorm): LlamaRMSNorm((3072,), eps=1e-05)
        (post_attention_layernorm): LlamaRMSNorm((3072,), eps=1e-05)
      )
    )
    (norm): LlamaRMSNorm((3072,), eps=1e-05)
    (rotary_emb): LlamaRotaryEmbedding()
  )
  (lm_head): Linear(in_features=3072, out_features=156951, bias=False)
)