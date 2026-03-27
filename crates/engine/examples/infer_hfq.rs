//! Run inference on a .hfq (hipfire-quantized) model.
//! Usage: cargo run --release --example infer_hfq <model.hfq> [prompt text...]

use engine::hfq::{self, HfqFile};
use engine::llama::{self, KvCache};
use std::io::Write;
use std::path::Path;
use std::time::Instant;

fn main() {
    let args: Vec<String> = std::env::args().collect();
    let model_path = args.get(1)
        .unwrap_or_else(|| { eprintln!("Usage: infer_hfq <model.hfq> [prompt...]"); std::process::exit(1); });

    // Parse --turbo flag
    let turbo_bits: u8 = args.iter().find(|a| a.starts_with("--turbo"))
        .map(|a| a.trim_start_matches("--turbo").parse().unwrap_or(3))
        .unwrap_or(0);

    let prompt_text = {
        let parts: Vec<&str> = args[2..].iter()
            .filter(|a| !a.starts_with("--turbo"))
            .map(|s| s.as_str()).collect();
        if parts.is_empty() { "Hello".to_string() } else { parts.join(" ") }
    };

    eprintln!("=== hipfire inference engine (HFQ) ===");
    eprintln!("Model: {model_path}");

    // Parse HFQ
    let hfq = HfqFile::open(Path::new(model_path)).expect("failed to parse HFQ");
    let config = hfq::config_from_hfq(&hfq).expect("failed to read model config");
    eprintln!("Config: dim={}, layers={}, heads={}, kv_heads={}, vocab={}",
        config.dim, config.n_layers, config.n_heads, config.n_kv_heads, config.vocab_size);

    // Load tokenizer from a matching GGUF (fallback until tokenizer is embedded in HFQ)
    let gguf_path = if config.arch == llama::ModelArch::Qwen3 {
        "/home/kaden/llama.cpp/models/Qwen3-0.6B-Q8_0.gguf"
    } else {
        "/home/kaden/llama.cpp/models/tinyllama-1.1b-chat-v1.0.Q4_K_M.gguf"
    };
    let gguf = engine::gguf::GgufFile::open(Path::new(gguf_path)).expect("need GGUF for tokenizer");
    let tokenizer = engine::tokenizer::Tokenizer::from_gguf(&gguf).expect("failed to load tokenizer");
    eprintln!("Tokenizer: {} tokens (from GGUF: {})", tokenizer.vocab_size(),
        std::path::Path::new(gguf_path).file_name().unwrap().to_str().unwrap());

    let mut prompt_tokens = tokenizer.encode(&prompt_text);

    // Qwen3 chat template: <|im_start|>user\n{prompt}<|im_end|>\n<|im_start|>assistant\n
    if config.arch == llama::ModelArch::Qwen3 {
        let im_start = tokenizer.encode("<|im_start|>");
        let im_end = tokenizer.encode("<|im_end|>");
        let user_tok = tokenizer.encode("user");
        let asst_tok = tokenizer.encode("assistant");
        let nl_tok = tokenizer.encode("\n");

        let mut chat = Vec::new();
        chat.extend_from_slice(&im_start);
        chat.extend_from_slice(&user_tok);
        chat.extend_from_slice(&nl_tok);
        chat.extend_from_slice(&prompt_tokens);
        chat.extend_from_slice(&im_end);
        chat.extend_from_slice(&nl_tok);
        chat.extend_from_slice(&im_start);
        chat.extend_from_slice(&asst_tok);
        chat.extend_from_slice(&nl_tok);
        prompt_tokens = chat;
    }

    eprintln!("Prompt: \"{}\" → {} tokens", prompt_text, prompt_tokens.len());

    // Init GPU
    let mut gpu = rdna_compute::Gpu::init().expect("GPU init failed");

    // Load weights from HFQ
    eprintln!("Loading weights...");
    let t0 = Instant::now();
    let weights = hfq::load_weights_hfq(&hfq, &config, &mut gpu).expect("failed to load weights");
    eprintln!("  Loaded in {:.1}s", t0.elapsed().as_secs_f64());

    // KV cache
    let kv_seq_len = config.max_seq_len.min(2048);
    let mut kv_cache = if turbo_bits > 0 {
        KvCache::new_gpu_turbo(
            &mut gpu, config.n_layers, config.n_kv_heads, config.head_dim, kv_seq_len, turbo_bits,
        ).unwrap()
    } else {
        KvCache::new_gpu(
            &mut gpu, config.n_layers, config.n_kv_heads, config.head_dim, kv_seq_len,
        ).unwrap()
    };

    // Process prompt
    let t1 = Instant::now();
    let mut logits = Vec::new();
    for (pos, &token) in prompt_tokens.iter().enumerate() {
        logits = llama::forward(&mut gpu, &weights, &config, token, pos, &mut kv_cache)
            .expect("forward pass failed");
    }
    let prompt_ms = t1.elapsed().as_millis();
    eprintln!("Prompt: {}ms ({} tokens, {:.0} tok/s)",
        prompt_ms, prompt_tokens.len(),
        prompt_tokens.len() as f64 / (prompt_ms as f64 / 1000.0));

    // Generate
    let max_gen = 128;
    eprintln!("\nGenerating (max {max_gen} tokens)...\n");
    let t2 = Instant::now();
    let mut next_token = llama::argmax(&logits);
    let mut generated = Vec::new();

    for _ in 0..max_gen {
        generated.push(next_token);
        let text = tokenizer.decode(&[next_token]);
        print!("{text}");
        std::io::stdout().flush().ok();

        if next_token == config.eos_token {
            break;
        }

        let pos = prompt_tokens.len() + generated.len() - 1;
        logits = llama::forward(&mut gpu, &weights, &config, next_token, pos, &mut kv_cache)
            .expect("forward pass failed");
        next_token = llama::argmax(&logits);
    }

    let gen_ms = t2.elapsed().as_millis();
    let tok_s = if gen_ms > 0 {
        generated.len() as f64 / (gen_ms as f64 / 1000.0)
    } else { 0.0 };

    eprintln!("\n\n=== Done: {} tokens in {}ms ({:.1} tok/s) ===",
        generated.len(), gen_ms, tok_s);
}
