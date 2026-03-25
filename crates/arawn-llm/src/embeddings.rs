//! Embeddings support for semantic search and memory.
//!
//! This module provides the [`Embedder`] trait and implementations for
//! generating vector embeddings from text. Embeddings are used for:
//! - Semantic search in the memory store
//! - Finding similar content
//! - Context retrieval for conversations
//!
//! # Implementations
//!
//! - [`MockEmbedder`]: Returns deterministic embeddings for testing
//! - [`LocalEmbedder`]: Uses ONNX Runtime for local inference (requires `local-embeddings` feature)
//! - [`OpenAiEmbedder`]: Uses OpenAI's embeddings API

use async_trait::async_trait;
use std::sync::Arc;

use crate::api_key::ApiKeyProvider;
use crate::error::Result;

// ─────────────────────────────────────────────────────────────────────────────
// Embedder Trait
// ─────────────────────────────────────────────────────────────────────────────

/// Trait for generating text embeddings.
///
/// Embedders convert text into dense vector representations that capture
/// semantic meaning, enabling similarity search and retrieval.
#[async_trait]
pub trait Embedder: Send + Sync {
    /// Generate an embedding for a single text.
    async fn embed(&self, text: &str) -> Result<Vec<f32>>;

    /// Generate embeddings for multiple texts in a batch.
    ///
    /// Default implementation calls `embed` for each text sequentially.
    /// Implementations may override for more efficient batching.
    async fn embed_batch(&self, texts: &[&str]) -> Result<Vec<Vec<f32>>> {
        let mut results = Vec::with_capacity(texts.len());
        for text in texts {
            results.push(self.embed(text).await?);
        }
        Ok(results)
    }

    /// Get the dimensionality of embeddings produced by this embedder.
    fn dimensions(&self) -> usize;

    /// Get the name of this embedder.
    fn name(&self) -> &str;
}

/// A shared embedder that can be used across threads.
pub type SharedEmbedder = Arc<dyn Embedder>;

// ─────────────────────────────────────────────────────────────────────────────
// Mock Embedder
// ─────────────────────────────────────────────────────────────────────────────

/// A mock embedder for testing purposes.
///
/// Generates deterministic embeddings based on text content, useful for
/// testing similarity search and memory retrieval without external dependencies.
#[derive(Debug, Clone)]
pub struct MockEmbedder {
    dimensions: usize,
}

impl MockEmbedder {
    /// Create a new mock embedder with the specified dimensions.
    pub fn new(dimensions: usize) -> Self {
        Self { dimensions }
    }

    /// Create a mock embedder with 384 dimensions (same as all-MiniLM-L6-v2).
    pub fn default_dimensions() -> Self {
        Self::new(384)
    }
}

impl Default for MockEmbedder {
    fn default() -> Self {
        Self::default_dimensions()
    }
}

#[async_trait]
impl Embedder for MockEmbedder {
    async fn embed(&self, text: &str) -> Result<Vec<f32>> {
        // Generate a deterministic embedding based on text hash
        // This ensures the same text always produces the same embedding
        let hash = simple_hash(text);
        let mut embedding = vec![0.0f32; self.dimensions];

        // Fill embedding with pseudo-random values based on hash
        let mut state = hash;
        for item in embedding.iter_mut().take(self.dimensions) {
            state = state.wrapping_mul(1103515245).wrapping_add(12345);
            *item = ((state >> 16) as f32 / 32768.0) - 1.0;
        }

        // Normalize to unit length
        let norm: f32 = embedding.iter().map(|x| x * x).sum::<f32>().sqrt();
        if norm > 0.0 {
            for x in &mut embedding {
                *x /= norm;
            }
        }

        Ok(embedding)
    }

    fn dimensions(&self) -> usize {
        self.dimensions
    }

    fn name(&self) -> &str {
        "mock"
    }
}

/// Simple hash function for deterministic embedding generation.
fn simple_hash(s: &str) -> u64 {
    let mut hash: u64 = 5381;
    for byte in s.bytes() {
        hash = hash.wrapping_mul(33).wrapping_add(byte as u64);
    }
    hash
}

// ─────────────────────────────────────────────────────────────────────────────
// OpenAI Embedder
// ─────────────────────────────────────────────────────────────────────────────

use reqwest::Client;
use std::time::Duration;

/// Configuration for OpenAI embeddings.
#[derive(Debug, Clone)]
pub struct OpenAiEmbedderConfig {
    /// API key for authentication. Supports hot-loading via `ApiKeyProvider::Dynamic`.
    pub api_key: ApiKeyProvider,
    /// Base URL for the API.
    pub base_url: String,
    /// Model to use for embeddings.
    pub model: String,
    /// Request timeout.
    pub timeout: Duration,
    /// Override output dimensions. When set, takes precedence over the
    /// built-in model→dimension lookup. Useful for custom/proxy endpoints
    /// or models not in the hardcoded map.
    pub dimensions: Option<usize>,
}

impl OpenAiEmbedderConfig {
    /// Create a new config with the given API key.
    pub fn new(api_key: impl Into<String>) -> Self {
        Self {
            api_key: ApiKeyProvider::from_static(api_key),
            base_url: "https://api.openai.com/v1".to_string(),
            model: "text-embedding-3-small".to_string(),
            timeout: Duration::from_secs(60),
            dimensions: None,
        }
    }

    /// Create config from environment variable.
    pub fn from_env() -> Result<Self> {
        let api_key = std::env::var("OPENAI_API_KEY").map_err(|_| {
            crate::error::LlmError::Config(
                "OPENAI_API_KEY environment variable not set".to_string(),
            )
        })?;
        Ok(Self::new(api_key))
    }

    /// Set a custom base URL.
    pub fn with_base_url(mut self, url: impl Into<String>) -> Self {
        self.base_url = url.into();
        self
    }

    /// Set the model to use.
    pub fn with_model(mut self, model: impl Into<String>) -> Self {
        self.model = model.into();
        self
    }

    /// Override output dimensions.
    pub fn with_dimensions(mut self, dimensions: usize) -> Self {
        self.dimensions = Some(dimensions);
        self
    }
}

/// OpenAI embeddings API client.
pub struct OpenAiEmbedder {
    client: Client,
    config: OpenAiEmbedderConfig,
    dimensions: usize,
}

impl OpenAiEmbedder {
    /// Create a new OpenAI embedder.
    pub fn new(config: OpenAiEmbedderConfig) -> Result<Self> {
        let client = Client::builder()
            .timeout(config.timeout)
            .build()
            .map_err(|e| {
                crate::error::LlmError::Internal(format!("Failed to create HTTP client: {}", e))
            })?;

        // Use explicit dimensions if provided, otherwise look up by model name
        let dimensions = config.dimensions.unwrap_or({
            match config.model.as_str() {
                "text-embedding-3-small" => 1536,
                "text-embedding-3-large" => 3072,
                "text-embedding-ada-002" => 1536,
                _ => 1536, // Default for unknown models
            }
        });

        Ok(Self {
            client,
            config,
            dimensions,
        })
    }

    /// Create from environment configuration.
    pub fn from_env() -> Result<Self> {
        Self::new(OpenAiEmbedderConfig::from_env()?)
    }

    fn embeddings_url(&self) -> String {
        format!("{}/embeddings", self.config.base_url)
    }
}

#[async_trait]
impl Embedder for OpenAiEmbedder {
    async fn embed(&self, text: &str) -> Result<Vec<f32>> {
        let results = self.embed_batch(&[text]).await?;
        results
            .into_iter()
            .next()
            .ok_or_else(|| crate::error::LlmError::Internal("No embedding returned".to_string()))
    }

    async fn embed_batch(&self, texts: &[&str]) -> Result<Vec<Vec<f32>>> {
        let request = EmbeddingRequest {
            model: self.config.model.clone(),
            input: texts.iter().map(|s| s.to_string()).collect(),
        };

        let api_key = self.config.api_key.resolve().ok_or_else(|| {
            crate::error::LlmError::Auth("OpenAI embedding API key not available.".to_string())
        })?;
        let response = self
            .client
            .post(self.embeddings_url())
            .header("Authorization", format!("Bearer {}", api_key))
            .header("Content-Type", "application/json")
            .json(&request)
            .send()
            .await?;

        if !response.status().is_success() {
            let status = response.status();
            let body = response.text().await.unwrap_or_default();
            return Err(crate::error::LlmError::Backend(format!(
                "Embedding request failed: HTTP {} - {}",
                status, body
            )));
        }

        let result: EmbeddingResponse = response.json().await.map_err(|e| {
            crate::error::LlmError::Serialization(format!("Failed to parse response: {}", e))
        })?;

        // Sort by index to ensure correct order
        let mut embeddings: Vec<_> = result.data.into_iter().collect();
        embeddings.sort_by_key(|e| e.index);

        Ok(embeddings.into_iter().map(|e| e.embedding).collect())
    }

    fn dimensions(&self) -> usize {
        self.dimensions
    }

    fn name(&self) -> &str {
        "openai"
    }
}

#[derive(Debug, serde::Serialize)]
struct EmbeddingRequest {
    model: String,
    input: Vec<String>,
}

#[derive(Debug, serde::Deserialize)]
struct EmbeddingResponse {
    data: Vec<EmbeddingData>,
}

#[derive(Debug, serde::Deserialize)]
struct EmbeddingData {
    index: usize,
    embedding: Vec<f32>,
}

// ─────────────────────────────────────────────────────────────────────────────
// Local Embedder (ONNX Runtime)
// ─────────────────────────────────────────────────────────────────────────────

#[cfg(feature = "local-embeddings")]
pub mod local {
    //! Local embeddings using ONNX Runtime.
    //!
    //! This module requires the `local-embeddings` feature to be enabled.

    use super::*;
    use ort::session::{Session, builder::GraphOptimizationLevel};
    use std::path::Path;
    use std::sync::Mutex;
    use tokenizers::Tokenizer;

    /// Local embedder using ONNX Runtime.
    ///
    /// This embedder runs inference locally using an ONNX model, enabling
    /// offline operation and avoiding API costs.
    ///
    /// The session is wrapped in a Mutex because ONNX Runtime's `run()` requires
    /// mutable access, but the Embedder trait uses `&self`.
    pub struct LocalEmbedder {
        session: Mutex<Session>,
        tokenizer: Tokenizer,
        dimensions: usize,
        name: String,
    }

    impl LocalEmbedder {
        /// Load a local embedder from model files.
        ///
        /// # Arguments
        /// * `model_path` - Path to the ONNX model file
        /// * `tokenizer_path` - Path to the tokenizer.json file
        /// * `dimensions` - Output embedding dimensions
        pub fn load(
            model_path: impl AsRef<Path>,
            tokenizer_path: impl AsRef<Path>,
            dimensions: usize,
        ) -> Result<Self> {
            let session = Session::builder()
                .map_err(|e| {
                    crate::error::LlmError::Internal(format!(
                        "Failed to create ONNX session: {}",
                        e
                    ))
                })?
                .with_optimization_level(GraphOptimizationLevel::Level3)
                .map_err(|e| {
                    crate::error::LlmError::Internal(format!(
                        "Failed to set optimization level: {}",
                        e
                    ))
                })?
                .commit_from_file(model_path.as_ref())
                .map_err(|e| {
                    crate::error::LlmError::Internal(format!(
                        "Failed to load ONNX model from {:?}: {}",
                        model_path.as_ref(),
                        e
                    ))
                })?;

            let tokenizer = Tokenizer::from_file(tokenizer_path.as_ref()).map_err(|e| {
                crate::error::LlmError::Internal(format!(
                    "Failed to load tokenizer from {:?}: {}",
                    tokenizer_path.as_ref(),
                    e
                ))
            })?;

            Ok(Self {
                session: Mutex::new(session),
                tokenizer,
                dimensions,
                name: "local".to_string(),
            })
        }
    }

    #[async_trait]
    impl Embedder for LocalEmbedder {
        async fn embed(&self, text: &str) -> Result<Vec<f32>> {
            let results = self.embed_batch(&[text]).await?;
            results.into_iter().next().ok_or_else(|| {
                crate::error::LlmError::Internal("No embedding returned".to_string())
            })
        }

        async fn embed_batch(&self, texts: &[&str]) -> Result<Vec<Vec<f32>>> {
            if texts.is_empty() {
                return Ok(Vec::new());
            }

            // Tokenize all inputs
            let encodings: Vec<_> = texts
                .iter()
                .map(|text| {
                    self.tokenizer.encode(*text, true).map_err(|e| {
                        crate::error::LlmError::Internal(format!("Tokenization failed: {}", e))
                    })
                })
                .collect::<Result<Vec<_>>>()?;

            // Process in chunks to avoid OOM on large batches
            let chunk_size = 32;
            let mut all_results = Vec::with_capacity(texts.len());

            for chunk in encodings.chunks(chunk_size) {
                let batch_results = self.run_batch(chunk)?;
                all_results.extend(batch_results);
            }

            Ok(all_results)
        }

        fn dimensions(&self) -> usize {
            self.dimensions
        }

        fn name(&self) -> &str {
            &self.name
        }
    }

    impl LocalEmbedder {
        /// Run ONNX inference on a batch of encodings.
        ///
        /// Pads all sequences to the same length and runs a single
        /// `session.run()` call with batched tensors.
        fn run_batch(&self, encodings: &[tokenizers::Encoding]) -> Result<Vec<Vec<f32>>> {
            let batch_size = encodings.len();

            // Find max sequence length for padding
            let max_len = encodings
                .iter()
                .map(|e| e.get_ids().len())
                .max()
                .unwrap_or(0);

            // Build padded 2D arrays: (batch_size, max_len)
            let mut input_ids_flat = vec![0i64; batch_size * max_len];
            let mut attention_mask_flat = vec![0i64; batch_size * max_len];
            let mut token_type_ids_flat = vec![0i64; batch_size * max_len];

            for (i, enc) in encodings.iter().enumerate() {
                let ids = enc.get_ids();
                let mask = enc.get_attention_mask();
                let types = enc.get_type_ids();
                let seq_len = ids.len();
                let offset = i * max_len;

                for j in 0..seq_len {
                    input_ids_flat[offset + j] = ids[j] as i64;
                    attention_mask_flat[offset + j] = mask[j] as i64;
                    token_type_ids_flat[offset + j] = types[j] as i64;
                }
                // Rest stays zero-padded
            }

            // Create tensors using (shape, Vec<T>) tuple form to avoid ndarray version issues
            let shape = [batch_size, max_len];
            let input_ids_tensor = ort::value::Tensor::from_array((shape, input_ids_flat))
                .map_err(|e| crate::error::LlmError::Internal(format!("Tensor error: {}", e)))?;
            let attention_mask_tensor =
                ort::value::Tensor::from_array((shape, attention_mask_flat.clone())).map_err(
                    |e| crate::error::LlmError::Internal(format!("Tensor error: {}", e)),
                )?;
            let token_type_ids_tensor =
                ort::value::Tensor::from_array((shape, token_type_ids_flat)).map_err(|e| {
                    crate::error::LlmError::Internal(format!("Tensor error: {}", e))
                })?;

            // Acquire the session lock for inference
            let mut session = self.session.lock().map_err(|e| {
                crate::error::LlmError::Internal(format!("Session lock poisoned: {}", e))
            })?;

            let outputs = session
                .run(ort::inputs![
                    "input_ids" => input_ids_tensor,
                    "attention_mask" => attention_mask_tensor,
                    "token_type_ids" => token_type_ids_tensor,
                ])
                .map_err(|e| {
                    crate::error::LlmError::Internal(format!("ONNX inference failed: {}", e))
                })?;

            let (shape, data) = outputs[0].try_extract_tensor::<f32>().map_err(|e| {
                crate::error::LlmError::Internal(format!("Output extraction failed: {}", e))
            })?;

            // Shape is (batch_size, seq_len, hidden_dim)
            // Shape derefs to &[i64]
            if shape.len() != 3 {
                return Err(crate::error::LlmError::Internal(format!(
                    "Expected 3D output tensor, got shape: {:?}",
                    &**shape
                )));
            }
            let _out_batch = shape[0] as usize;
            let seq_len_out = shape[1] as usize;
            let hidden_dim = shape[2] as usize;

            // Data is laid out as: [batch0_seq0_hidden..., batch0_seq1_hidden..., batch1_seq0_hidden..., ...]
            let stride_batch = seq_len_out * hidden_dim;
            let stride_seq = hidden_dim;

            let mut results = Vec::with_capacity(batch_size);

            for i in 0..batch_size {
                // This sample's attention mask
                let mask_slice = &attention_mask_flat[i * max_len..(i + 1) * max_len];

                // Mean pooling with attention mask
                let mut sum = vec![0.0f32; hidden_dim];
                let mut count = 0.0f32;

                for (j, &mask_val) in mask_slice.iter().enumerate() {
                    if j >= seq_len_out {
                        break; // Don't exceed output sequence length
                    }
                    if mask_val > 0 {
                        // Get embedding for position j in sample i
                        let offset = i * stride_batch + j * stride_seq;
                        for k in 0..hidden_dim {
                            sum[k] += data[offset + k];
                        }
                        count += 1.0;
                    }
                }

                if count > 0.0 {
                    for v in &mut sum {
                        *v /= count;
                    }
                }

                // L2 normalize
                let norm: f32 = sum.iter().map(|x| x * x).sum::<f32>().sqrt();
                if norm > 1e-9 {
                    for v in &mut sum {
                        *v /= norm;
                    }
                }

                results.push(sum);
            }

            Ok(results)
        }
    }
}

// ─────────────────────────────────────────────────────────────────────────────
// Embedder Factory
// ─────────────────────────────────────────────────────────────────────────────

/// Configuration for building an embedder from application config.
///
/// This is a provider-agnostic struct that `start.rs` populates from
/// `EmbeddingConfig`. It avoids a dependency from arawn-llm → arawn-config.
#[derive(Debug, Clone)]
pub struct EmbedderSpec {
    /// Provider name: "local", "openai", or "mock".
    pub provider: String,
    /// OpenAI API key (required for "openai" provider).
    pub openai_api_key: Option<String>,
    /// OpenAI model name.
    pub openai_model: Option<String>,
    /// OpenAI base URL override.
    pub openai_base_url: Option<String>,
    /// Local ONNX model path.
    pub local_model_path: Option<std::path::PathBuf>,
    /// Local tokenizer.json path.
    pub local_tokenizer_path: Option<std::path::PathBuf>,
    /// Requested dimensions (for providers that support it).
    pub dimensions: Option<usize>,
    /// Override download URL for the local ONNX model file.
    pub local_model_url: Option<String>,
    /// Override download URL for the local tokenizer JSON file.
    pub local_tokenizer_url: Option<String>,
}

/// Build a `SharedEmbedder` from a spec.
///
/// Falls back to `MockEmbedder` if the requested provider is unavailable
/// (e.g., "local" requested but `local-embeddings` feature disabled).
///
/// For local embeddings, this will automatically download model files
/// from HuggingFace if they don't exist (~22MB).
pub async fn build_embedder(spec: &EmbedderSpec) -> Result<SharedEmbedder> {
    match spec.provider.as_str() {
        "openai" => {
            let api_key = spec.openai_api_key.as_deref().ok_or_else(|| {
                crate::error::LlmError::Config(
                    "OpenAI embedding provider requires an API key. \
                     Set OPENAI_API_KEY or configure [embedding.openai] api_key."
                        .to_string(),
                )
            })?;
            let mut config = OpenAiEmbedderConfig::new(api_key);
            if let Some(ref model) = spec.openai_model {
                config = config.with_model(model);
            }
            if let Some(ref base_url) = spec.openai_base_url {
                config = config.with_base_url(base_url);
            }
            if let Some(dimensions) = spec.dimensions {
                config = config.with_dimensions(dimensions);
            }
            Ok(Arc::new(OpenAiEmbedder::new(config)?))
        }
        #[cfg(feature = "local-embeddings")]
        "local" => {
            let dims = spec.dimensions.unwrap_or(384);

            // First try explicit paths from config
            if let (Some(model_path), Some(tokenizer_path)) =
                (&spec.local_model_path, &spec.local_tokenizer_path)
            {
                let embedder = local::LocalEmbedder::load(model_path, tokenizer_path, dims)?;
                return Ok(Arc::new(embedder));
            }

            // Try to ensure model files exist (downloads if missing)
            if let Some(dir) = ensure_model_files(
                spec.local_model_url.as_deref(),
                spec.local_tokenizer_url.as_deref(),
            )
            .await
            {
                let model_path = dir.join("model.onnx");
                let tokenizer_path = dir.join("tokenizer.json");
                if model_path.exists() && tokenizer_path.exists() {
                    match local::LocalEmbedder::load(&model_path, &tokenizer_path, dims) {
                        Ok(embedder) => {
                            tracing::info!("Local embeddings loaded (all-MiniLM-L6-v2)");
                            return Ok(Arc::new(embedder));
                        }
                        Err(e) => {
                            tracing::warn!("Failed to load local embedder: {}", e);
                        }
                    }
                }
            }

            // Fallback to mock
            tracing::info!(
                "Using mock embeddings (semantic search will use deterministic matching)"
            );
            Ok(Arc::new(MockEmbedder::new(dims)))
        }
        #[cfg(not(feature = "local-embeddings"))]
        "local" => {
            tracing::info!(
                "Local embeddings not available (feature disabled), using mock embeddings"
            );
            let dims = spec.dimensions.unwrap_or(384);
            Ok(Arc::new(MockEmbedder::new(dims)))
        }
        "mock" => {
            let dims = spec.dimensions.unwrap_or(384);
            tracing::info!("Using mock embeddings (configured)");
            Ok(Arc::new(MockEmbedder::new(dims)))
        }
        other => Err(crate::error::LlmError::Config(format!(
            "Unknown embedding provider '{}'. Valid: local, openai, mock",
            other
        ))),
    }
}

/// Default directory for local embedding model files.
#[cfg(feature = "local-embeddings")]
fn default_local_model_dir() -> Option<std::path::PathBuf> {
    dirs::data_dir().map(|d| d.join("arawn").join("models").join("embeddings"))
}

// ─────────────────────────────────────────────────────────────────────────────
// Model Download
// ─────────────────────────────────────────────────────────────────────────────

/// Default HuggingFace model URL for all-MiniLM-L6-v2 ONNX model.
pub const DEFAULT_EMBEDDING_MODEL_URL: &str =
    "https://huggingface.co/sentence-transformers/all-MiniLM-L6-v2/resolve/main/onnx/model.onnx";
/// Default HuggingFace tokenizer URL for all-MiniLM-L6-v2.
pub const DEFAULT_EMBEDDING_TOKENIZER_URL: &str =
    "https://huggingface.co/sentence-transformers/all-MiniLM-L6-v2/resolve/main/tokenizer.json";

/// Default HuggingFace model URL for GLiNER small v2.1 (span mode).
pub const DEFAULT_NER_MODEL_URL: &str =
    "https://huggingface.co/onnx-community/gliner_small-v2.1/resolve/main/onnx/model.onnx";
/// Default HuggingFace tokenizer URL for GLiNER small v2.1.
pub const DEFAULT_NER_TOKENIZER_URL: &str =
    "https://huggingface.co/onnx-community/gliner_small-v2.1/resolve/main/tokenizer.json";

/// Download embedding model files if they don't exist.
///
/// Returns the directory path where files were downloaded, or None if download failed.
/// Accepts optional URL overrides; falls back to HuggingFace defaults.
#[cfg(feature = "local-embeddings")]
async fn ensure_model_files(
    model_url: Option<&str>,
    tokenizer_url: Option<&str>,
) -> Option<std::path::PathBuf> {
    let dir = default_local_model_dir()?;
    let model_path = dir.join("model.onnx");
    let tokenizer_path = dir.join("tokenizer.json");

    // Check if files already exist
    if model_path.exists() && tokenizer_path.exists() {
        return Some(dir);
    }

    // Create directory if needed
    if let Err(e) = std::fs::create_dir_all(&dir) {
        tracing::warn!("Failed to create model directory: {}", e);
        return None;
    }

    let model_url = model_url.unwrap_or(DEFAULT_EMBEDDING_MODEL_URL);
    let tokenizer_url = tokenizer_url.unwrap_or(DEFAULT_EMBEDDING_TOKENIZER_URL);

    tracing::info!("Downloading embedding model...");

    // Download model file
    if !model_path.exists() {
        if let Err(e) = download_file(model_url, &model_path).await {
            tracing::warn!("Failed to download model.onnx: {}", e);
            return None;
        }
        tracing::info!("Downloaded model.onnx");
    }

    // Download tokenizer
    if !tokenizer_path.exists() {
        if let Err(e) = download_file(tokenizer_url, &tokenizer_path).await {
            tracing::warn!("Failed to download tokenizer.json: {}", e);
            // Clean up partial download
            let _ = std::fs::remove_file(&model_path);
            return None;
        }
        tracing::info!("Downloaded tokenizer.json");
    }

    tracing::info!("Embedding model ready");
    Some(dir)
}

/// Default directory for NER (GLiNER) model files.
pub fn default_ner_model_dir() -> Option<std::path::PathBuf> {
    dirs::data_dir().map(|d| d.join("arawn").join("models").join("ner"))
}

/// Download NER (GLiNER) model files if they don't exist.
///
/// Returns `(model_path, tokenizer_path)` or None if download failed.
/// Accepts optional URL overrides; falls back to HuggingFace defaults.
pub async fn ensure_ner_model_files(
    model_url: Option<&str>,
    tokenizer_url: Option<&str>,
) -> Option<(std::path::PathBuf, std::path::PathBuf)> {
    let dir = default_ner_model_dir()?;
    let model_path = dir.join("model.onnx");
    let tok_path = dir.join("tokenizer.json");

    // Check if files already exist
    if model_path.exists() && tok_path.exists() {
        return Some((model_path, tok_path));
    }

    // Create directory if needed
    if let Err(e) = std::fs::create_dir_all(&dir) {
        tracing::warn!("Failed to create NER model directory: {}", e);
        return None;
    }

    let model_url = model_url.unwrap_or(DEFAULT_NER_MODEL_URL);
    let tokenizer_url = tokenizer_url.unwrap_or(DEFAULT_NER_TOKENIZER_URL);

    tracing::info!("Downloading NER model (GLiNER small v2.1)...");

    // Download model file
    if !model_path.exists() {
        if let Err(e) = download_file(model_url, &model_path).await {
            tracing::warn!("Failed to download NER model.onnx: {}", e);
            return None;
        }
        tracing::info!("Downloaded NER model.onnx");
    }

    // Download tokenizer
    if !tok_path.exists() {
        if let Err(e) = download_file(tokenizer_url, &tok_path).await {
            tracing::warn!("Failed to download NER tokenizer.json: {}", e);
            let _ = std::fs::remove_file(&model_path);
            return None;
        }
        tracing::info!("Downloaded NER tokenizer.json");
    }

    tracing::info!("NER model ready");
    Some((model_path, tok_path))
}

/// Download a file from URL to path.
pub async fn download_file(url: &str, path: &std::path::Path) -> Result<()> {
    use std::io::Write;

    let client = Client::builder()
        .timeout(Duration::from_secs(300)) // 5 min timeout for large files
        .build()
        .map_err(|e| crate::error::LlmError::Internal(format!("HTTP client error: {}", e)))?;

    let response =
        client.get(url).send().await.map_err(|e| {
            crate::error::LlmError::Internal(format!("Download request failed: {}", e))
        })?;

    if !response.status().is_success() {
        return Err(crate::error::LlmError::Internal(format!(
            "Download failed: HTTP {}",
            response.status()
        )));
    }

    let bytes = response
        .bytes()
        .await
        .map_err(|e| crate::error::LlmError::Internal(format!("Failed to read response: {}", e)))?;

    // Write to temp file first, then rename for atomicity
    let temp_path = path.with_extension("tmp");
    let mut file = std::fs::File::create(&temp_path)
        .map_err(|e| crate::error::LlmError::Internal(format!("Failed to create file: {}", e)))?;

    file.write_all(&bytes)
        .map_err(|e| crate::error::LlmError::Internal(format!("Failed to write file: {}", e)))?;

    std::fs::rename(&temp_path, path)
        .map_err(|e| crate::error::LlmError::Internal(format!("Failed to rename file: {}", e)))?;

    Ok(())
}

// ─────────────────────────────────────────────────────────────────────────────
// Utility Functions
// ─────────────────────────────────────────────────────────────────────────────

/// Calculate cosine similarity between two embeddings.
pub fn cosine_similarity(a: &[f32], b: &[f32]) -> f32 {
    if a.len() != b.len() {
        return 0.0;
    }

    let dot: f32 = a.iter().zip(b.iter()).map(|(x, y)| x * y).sum();
    let norm_a: f32 = a.iter().map(|x| x * x).sum::<f32>().sqrt();
    let norm_b: f32 = b.iter().map(|x| x * x).sum::<f32>().sqrt();

    if norm_a > 0.0 && norm_b > 0.0 {
        dot / (norm_a * norm_b)
    } else {
        0.0
    }
}

/// Calculate Euclidean distance between two embeddings.
pub fn euclidean_distance(a: &[f32], b: &[f32]) -> f32 {
    if a.len() != b.len() {
        return f32::MAX;
    }

    a.iter()
        .zip(b.iter())
        .map(|(x, y)| (x - y).powi(2))
        .sum::<f32>()
        .sqrt()
}

// ─────────────────────────────────────────────────────────────────────────────
// Tests
// ─────────────────────────────────────────────────────────────────────────────

#[cfg(test)]
mod tests {
    use super::*;

    #[tokio::test]
    async fn test_mock_embedder() {
        let embedder = MockEmbedder::default();
        assert_eq!(embedder.dimensions(), 384);
        assert_eq!(embedder.name(), "mock");

        let embedding = embedder.embed("hello world").await.unwrap();
        assert_eq!(embedding.len(), 384);

        // Check normalization (should be unit length)
        let norm: f32 = embedding.iter().map(|x| x * x).sum::<f32>().sqrt();
        assert!((norm - 1.0).abs() < 0.001);
    }

    #[tokio::test]
    async fn test_mock_embedder_deterministic() {
        let embedder = MockEmbedder::default();

        let e1 = embedder.embed("test text").await.unwrap();
        let e2 = embedder.embed("test text").await.unwrap();

        // Same text should produce same embedding
        assert_eq!(e1, e2);
    }

    #[tokio::test]
    async fn test_mock_embedder_different_texts() {
        let embedder = MockEmbedder::default();

        let e1 = embedder.embed("hello").await.unwrap();
        let e2 = embedder.embed("world").await.unwrap();

        // Different texts should produce different embeddings
        assert_ne!(e1, e2);
    }

    #[tokio::test]
    async fn test_embed_batch() {
        let embedder = MockEmbedder::default();

        let texts = vec!["one", "two", "three"];
        let embeddings = embedder.embed_batch(&texts).await.unwrap();

        assert_eq!(embeddings.len(), 3);
        for emb in &embeddings {
            assert_eq!(emb.len(), 384);
        }
    }

    #[test]
    fn test_cosine_similarity() {
        let a = vec![1.0, 0.0, 0.0];
        let b = vec![1.0, 0.0, 0.0];
        assert!((cosine_similarity(&a, &b) - 1.0).abs() < 0.001);

        let c = vec![0.0, 1.0, 0.0];
        assert!(cosine_similarity(&a, &c).abs() < 0.001);

        let d = vec![-1.0, 0.0, 0.0];
        assert!((cosine_similarity(&a, &d) + 1.0).abs() < 0.001);
    }

    #[test]
    fn test_euclidean_distance() {
        let a = vec![0.0, 0.0, 0.0];
        let b = vec![3.0, 4.0, 0.0];
        assert!((euclidean_distance(&a, &b) - 5.0).abs() < 0.001);

        let c = vec![0.0, 0.0, 0.0];
        assert!(euclidean_distance(&a, &c).abs() < 0.001);
    }

    #[test]
    fn test_openai_embedder_config() {
        let config = OpenAiEmbedderConfig::new("test-key");
        assert_eq!(config.api_key.resolve(), Some("test-key".to_string()));
        assert_eq!(config.model, "text-embedding-3-small");
    }

    #[test]
    fn test_openai_embedder_config_builder() {
        let config = OpenAiEmbedderConfig::new("key")
            .with_base_url("http://custom.api")
            .with_model("text-embedding-ada-002");

        assert_eq!(config.base_url, "http://custom.api");
        assert_eq!(config.model, "text-embedding-ada-002");
        assert_eq!(config.dimensions, None);
    }

    #[test]
    fn test_openai_embedder_dimensions_from_model_lookup() {
        // Known models use hardcoded dimensions
        let embedder = OpenAiEmbedder::new(OpenAiEmbedderConfig::new("key")).unwrap();
        assert_eq!(embedder.dimensions(), 1536); // text-embedding-3-small default

        let embedder = OpenAiEmbedder::new(
            OpenAiEmbedderConfig::new("key").with_model("text-embedding-3-large"),
        )
        .unwrap();
        assert_eq!(embedder.dimensions(), 3072);
    }

    #[test]
    fn test_openai_embedder_dimensions_override() {
        // Explicit dimensions override the model lookup
        let config = OpenAiEmbedderConfig::new("key")
            .with_model("text-embedding-3-small")
            .with_dimensions(512);
        let embedder = OpenAiEmbedder::new(config).unwrap();
        assert_eq!(embedder.dimensions(), 512);
    }

    #[test]
    fn test_openai_embedder_dimensions_override_unknown_model() {
        // Custom model with explicit dimensions
        let config = OpenAiEmbedderConfig::new("key")
            .with_model("my-custom-embedding-model")
            .with_dimensions(768);
        let embedder = OpenAiEmbedder::new(config).unwrap();
        assert_eq!(embedder.dimensions(), 768);
    }

    #[test]
    fn test_embed_auth_header() {
        let key = "sk-embed-test-key-12345";
        let config = OpenAiEmbedderConfig::new(key);
        let embedder = OpenAiEmbedder::new(config).unwrap();

        // Build a request manually the same way embed_batch does
        let api_key = embedder.config.api_key.resolve().unwrap();
        let req = embedder
            .client
            .post(embedder.embeddings_url())
            .header("Authorization", format!("Bearer {}", api_key))
            .header("Content-Type", "application/json")
            .build()
            .unwrap();

        let auth = req
            .headers()
            .get("authorization")
            .unwrap()
            .to_str()
            .unwrap();
        assert_eq!(auth, format!("Bearer {}", key));
    }

    #[test]
    fn test_embed_auth_header_dynamic_provider() {
        let key = "sk-embed-dynamic-key";
        let mut config = OpenAiEmbedderConfig::new("placeholder");
        config.api_key = crate::api_key::ApiKeyProvider::dynamic(move || Some(key.to_string()));
        let embedder = OpenAiEmbedder::new(config).unwrap();

        let api_key = embedder.config.api_key.resolve().unwrap();
        let req = embedder
            .client
            .post(embedder.embeddings_url())
            .header("Authorization", format!("Bearer {}", api_key))
            .build()
            .unwrap();

        let auth = req
            .headers()
            .get("authorization")
            .unwrap()
            .to_str()
            .unwrap();
        assert_eq!(auth, format!("Bearer {}", key));
    }

    // ── build_embedder factory tests ──────────────────────────────────────

    #[tokio::test]
    async fn test_build_embedder_mock() {
        let spec = EmbedderSpec {
            provider: "mock".to_string(),
            openai_api_key: None,
            openai_model: None,
            openai_base_url: None,
            local_model_path: None,
            local_tokenizer_path: None,
            dimensions: Some(128),
            local_model_url: None,
            local_tokenizer_url: None,
        };
        let embedder = build_embedder(&spec).await.unwrap();
        assert_eq!(embedder.name(), "mock");
        assert_eq!(embedder.dimensions(), 128);
    }

    #[tokio::test]
    async fn test_build_embedder_mock_default_dims() {
        let spec = EmbedderSpec {
            provider: "mock".to_string(),
            openai_api_key: None,
            openai_model: None,
            openai_base_url: None,
            local_model_path: None,
            local_tokenizer_path: None,
            dimensions: None,
            local_model_url: None,
            local_tokenizer_url: None,
        };
        let embedder = build_embedder(&spec).await.unwrap();
        assert_eq!(embedder.dimensions(), 384);
    }

    #[tokio::test]
    async fn test_build_embedder_unknown_provider() {
        let spec = EmbedderSpec {
            provider: "nonexistent".to_string(),
            openai_api_key: None,
            openai_model: None,
            openai_base_url: None,
            local_model_path: None,
            local_tokenizer_path: None,
            dimensions: None,
            local_model_url: None,
            local_tokenizer_url: None,
        };
        let result = build_embedder(&spec).await;
        assert!(result.is_err());
        let msg = result.err().unwrap().to_string();
        assert!(
            msg.contains("nonexistent"),
            "Error should mention provider: {}",
            msg
        );
    }

    #[tokio::test]
    async fn test_build_embedder_openai_no_key() {
        let spec = EmbedderSpec {
            provider: "openai".to_string(),
            openai_api_key: None,
            openai_model: None,
            openai_base_url: None,
            local_model_path: None,
            local_tokenizer_path: None,
            dimensions: None,
            local_model_url: None,
            local_tokenizer_url: None,
        };
        let result = build_embedder(&spec).await;
        assert!(result.is_err());
        let msg = result.err().unwrap().to_string();
        assert!(
            msg.contains("API key"),
            "Error should mention API key: {}",
            msg
        );
    }

    #[tokio::test]
    async fn test_build_embedder_openai_with_config() {
        let spec = EmbedderSpec {
            provider: "openai".to_string(),
            openai_api_key: Some("test-key".to_string()),
            openai_model: Some("text-embedding-ada-002".to_string()),
            openai_base_url: Some("http://localhost:8080/v1".to_string()),
            local_model_path: None,
            local_tokenizer_path: None,
            dimensions: Some(256),
            local_model_url: None,
            local_tokenizer_url: None,
        };
        let embedder = build_embedder(&spec).await.unwrap();
        assert_eq!(embedder.name(), "openai");
        assert_eq!(embedder.dimensions(), 256);
    }

    #[tokio::test]
    async fn test_build_embedder_local_without_feature() {
        // When local-embeddings feature is disabled, "local" falls back to mock
        let spec = EmbedderSpec {
            provider: "local".to_string(),
            openai_api_key: None,
            openai_model: None,
            openai_base_url: None,
            local_model_path: None,
            local_tokenizer_path: None,
            dimensions: Some(64),
            local_model_url: None,
            local_tokenizer_url: None,
        };
        let embedder = build_embedder(&spec).await.unwrap();
        // Falls back to mock when feature disabled OR model files missing
        assert_eq!(embedder.dimensions(), 64);
    }

    // ── OpenAiEmbedder method tests ───────────────────────────────────────

    #[test]
    fn test_openai_embedder_name() {
        let embedder = OpenAiEmbedder::new(OpenAiEmbedderConfig::new("key")).unwrap();
        assert_eq!(embedder.name(), "openai");
    }

    #[test]
    fn test_openai_embedder_embeddings_url() {
        let config = OpenAiEmbedderConfig::new("key").with_base_url("http://localhost:8080/v1");
        let embedder = OpenAiEmbedder::new(config).unwrap();
        assert_eq!(
            embedder.embeddings_url(),
            "http://localhost:8080/v1/embeddings"
        );
    }

    #[test]
    fn test_openai_embedder_embeddings_url_default() {
        let embedder = OpenAiEmbedder::new(OpenAiEmbedderConfig::new("key")).unwrap();
        assert_eq!(
            embedder.embeddings_url(),
            "https://api.openai.com/v1/embeddings"
        );
    }

    // ── MockEmbedder tests ────────────────────────────────────────────────

    #[tokio::test]
    async fn test_mock_embedder_custom_dimensions() {
        let embedder = MockEmbedder::new(16);
        assert_eq!(embedder.dimensions(), 16);
        let emb = embedder.embed("test").await.unwrap();
        assert_eq!(emb.len(), 16);
        // Verify normalization
        let norm: f32 = emb.iter().map(|x| x * x).sum::<f32>().sqrt();
        assert!((norm - 1.0).abs() < 0.001);
    }

    #[tokio::test]
    async fn test_mock_embedder_default_impl() {
        let embedder = MockEmbedder::default();
        assert_eq!(embedder.dimensions(), 384);
        assert_eq!(embedder.name(), "mock");
    }

    #[tokio::test]
    async fn test_mock_embedder_embed_batch_empty() {
        let embedder = MockEmbedder::default();
        let results = embedder.embed_batch(&[]).await.unwrap();
        assert!(results.is_empty());
    }

    // ── Similarity edge cases ─────────────────────────────────────────────

    #[test]
    fn test_cosine_similarity_mismatched_lengths() {
        let a = vec![1.0, 0.0];
        let b = vec![1.0, 0.0, 0.0];
        assert_eq!(cosine_similarity(&a, &b), 0.0);
    }

    #[test]
    fn test_cosine_similarity_zero_vectors() {
        let a = vec![0.0, 0.0, 0.0];
        let b = vec![1.0, 0.0, 0.0];
        assert_eq!(cosine_similarity(&a, &b), 0.0);
        assert_eq!(cosine_similarity(&a, &a), 0.0);
    }

    #[test]
    fn test_euclidean_distance_mismatched_lengths() {
        let a = vec![1.0, 0.0];
        let b = vec![1.0, 0.0, 0.0];
        assert_eq!(euclidean_distance(&a, &b), f32::MAX);
    }

    #[test]
    fn test_euclidean_distance_identical() {
        let a = vec![3.0, 4.0, 5.0];
        assert!(euclidean_distance(&a, &a).abs() < f32::EPSILON);
    }

    // ── EmbedderSpec construction ─────────────────────────────────────────

    #[test]
    fn test_embedder_spec_debug() {
        let spec = EmbedderSpec {
            provider: "mock".to_string(),
            openai_api_key: None,
            openai_model: None,
            openai_base_url: None,
            local_model_path: None,
            local_tokenizer_path: None,
            dimensions: None,
            local_model_url: None,
            local_tokenizer_url: None,
        };
        let debug = format!("{:?}", spec);
        assert!(debug.contains("mock"));
    }

    // ── OpenAiEmbedderConfig edge cases ───────────────────────────────────

    #[test]
    fn test_openai_config_with_dimensions() {
        let config = OpenAiEmbedderConfig::new("key").with_dimensions(512);
        assert_eq!(config.dimensions, Some(512));
    }

    #[test]
    fn test_openai_config_timeout() {
        let config = OpenAiEmbedderConfig::new("key");
        assert_eq!(config.timeout, Duration::from_secs(60));
    }

    // ── simple_hash ──────────────────────────────────────────────────────

    #[test]
    fn test_simple_hash_deterministic() {
        assert_eq!(simple_hash("hello"), simple_hash("hello"));
        assert_ne!(simple_hash("hello"), simple_hash("world"));
    }

    #[test]
    fn test_simple_hash_empty() {
        // Empty string should produce the initial seed value
        let h = simple_hash("");
        assert_eq!(h, 5381);
    }

    // ── default_ner_model_dir ─────────────────────────────────────────────

    #[test]
    fn test_default_ner_model_dir_returns_some() {
        // On most systems dirs::data_dir() returns Some
        let dir = default_ner_model_dir();
        if let Some(d) = dir {
            assert!(d.ends_with("arawn/models/ner") || d.to_string_lossy().contains("arawn"));
        }
    }

    // ── Constants ─────────────────────────────────────────────────────────

    #[test]
    fn test_model_url_constants() {
        assert!(DEFAULT_EMBEDDING_MODEL_URL.contains("huggingface.co"));
        assert!(DEFAULT_EMBEDDING_TOKENIZER_URL.contains("tokenizer.json"));
        assert!(DEFAULT_NER_MODEL_URL.contains("gliner"));
        assert!(DEFAULT_NER_TOKENIZER_URL.contains("tokenizer.json"));
    }
}
