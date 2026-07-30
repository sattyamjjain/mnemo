//! Local **Ollama** embedder shared across the real-embedder benches
//! (`semantic_recall_bench`, `implicit_association`). Calls Ollama's HTTP
//! `/api/embeddings` endpoint; the model dimensionality is probed at
//! [`OllamaEmbedding::connect`] and reported via [`EmbeddingProvider::dimensions`].
//!
//! Extracted verbatim from `semantic_recall_bench` in v0.5.20 so a second
//! real-embedder bench does not duplicate it. Behaviour is unchanged: same
//! default model (`nomic-embed-text`), same request shape, same
//! "is Ollama running and the model pulled?" error text.

use mnemo_core::embedding::EmbeddingProvider;
use mnemo_core::error::{Error, Result as MnemoResult};

/// A real semantic embedder backed by a local Ollama server.
pub struct OllamaEmbedding {
    client: reqwest::Client,
    url: String,
    model: String,
    dimensions: usize,
}

impl OllamaEmbedding {
    /// Connect and probe the model's output dimensionality. Fails with an
    /// actionable message if the server is down or the model is not pulled.
    pub async fn connect(url: String, model: String) -> MnemoResult<Self> {
        let client = reqwest::Client::builder()
            .timeout(std::time::Duration::from_secs(30))
            .build()
            .map_err(|e| Error::Embedding(format!("http client: {e}")))?;
        let probe = Self {
            client,
            url,
            model,
            dimensions: 0,
        };
        let v = probe.embed_raw("dimensionality probe").await.map_err(|e| {
            Error::Embedding(format!(
                "{e} — is Ollama running and the model pulled? Try: `ollama pull {}`",
                probe.model
            ))
        })?;
        let dimensions = v.len();
        if dimensions == 0 {
            return Err(Error::Embedding(
                "embedder returned a 0-length vector".into(),
            ));
        }
        Ok(Self {
            dimensions,
            ..probe
        })
    }

    async fn embed_raw(&self, text: &str) -> MnemoResult<Vec<f32>> {
        let resp = self
            .client
            .post(&self.url)
            .json(&serde_json::json!({ "model": self.model, "prompt": text }))
            .send()
            .await
            .map_err(|e| Error::Embedding(format!("ollama request failed: {e}")))?;
        if !resp.status().is_success() {
            return Err(Error::Embedding(format!(
                "ollama returned HTTP {}",
                resp.status()
            )));
        }
        let body: serde_json::Value = resp
            .json()
            .await
            .map_err(|e| Error::Embedding(format!("ollama response decode: {e}")))?;
        let arr = body
            .get("embedding")
            .and_then(|e| e.as_array())
            .ok_or_else(|| Error::Embedding("response missing 'embedding' array".into()))?;
        Ok(arr
            .iter()
            .map(|x| x.as_f64().unwrap_or(0.0) as f32)
            .collect())
    }
}

#[async_trait::async_trait]
impl EmbeddingProvider for OllamaEmbedding {
    async fn embed(&self, text: &str) -> MnemoResult<Vec<f32>> {
        self.embed_raw(text).await
    }
    async fn embed_batch(&self, texts: &[&str]) -> MnemoResult<Vec<Vec<f32>>> {
        let mut out = Vec::with_capacity(texts.len());
        for t in texts {
            out.push(self.embed_raw(t).await?);
        }
        Ok(out)
    }
    fn dimensions(&self) -> usize {
        self.dimensions
    }
}
