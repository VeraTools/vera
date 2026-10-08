//! Shared search service used by both CLI and MCP.
//!
//! Encapsulates the common hybrid search flow: create embedding provider,
//! resolve the reranker for the query, compute fetch limits, execute search,
//! apply filters.

use std::path::{Path, PathBuf};
use std::sync::{Arc, Mutex};
use std::time::{Duration, Instant};

use anyhow::Result;
use tokio::sync::OnceCell;
use tracing::warn;

use crate::config::{InferenceBackend, VeraConfig};
use crate::embedding::{CachedEmbeddingProvider, DynamicProvider, EmbeddingProvider};
use crate::retrieval::dynamic_reranker::DynamicReranker;
use crate::retrieval::exact_matches::augment_exact_match_candidates_with_store_and_config;
pub use crate::retrieval::exact_matches::augment_multi_query_exact_matches;
use crate::retrieval::hybrid::{SearchStores, compute_vector_candidates};
use crate::retrieval::query_classifier::{QueryType, classify_query, params_for_query_type};
use crate::retrieval::ranking::{RankingStage, is_path_weighted_query};
use crate::retrieval::{RerankOutcome, apply_filters, search_bm25_with_stores_and_filters};
use crate::types::{SearchFilters, SearchResult};

/// Timing data for each stage of the search pipeline.
#[derive(Debug, Default)]
pub struct SearchTimings {
    pub rerank_outcome: RerankOutcome,
    pub embedding: Option<Duration>,
    pub bm25: Option<Duration>,
    pub vector: Option<Duration>,
    pub fusion: Option<Duration>,
    pub reranking: Option<Duration>,
    pub augmentation: Option<Duration>,
    pub total: Option<Duration>,
}

impl SearchTimings {
    /// Aggregate per-search stages, leaving the request's total to its caller.
    pub fn merge(&mut self, incoming: &Self) {
        self.rerank_outcome.merge(&incoming.rerank_outcome);
        for (target, delta) in [
            (&mut self.embedding, incoming.embedding),
            (&mut self.bm25, incoming.bm25),
            (&mut self.vector, incoming.vector),
            (&mut self.fusion, incoming.fusion),
            (&mut self.reranking, incoming.reranking),
            (&mut self.augmentation, incoming.augmentation),
        ] {
            if let Some(delta) = delta {
                *target = Some(target.unwrap_or_default() + delta);
            }
        }
    }
}

impl From<crate::retrieval::hybrid::HybridTimings> for SearchTimings {
    fn from(t: crate::retrieval::hybrid::HybridTimings) -> Self {
        SearchTimings {
            rerank_outcome: t.rerank_outcome,
            embedding: t.embedding,
            bm25: t.bm25,
            vector: t.vector,
            fusion: t.fusion,
            reranking: t.reranking,
            augmentation: None,
            total: None,
        }
    }
}

/// Reusable search dependencies for a process or command invocation.
///
/// Local backends can take hundreds of milliseconds or seconds to initialize.
/// Keeping the provider and reranker here lets CLI multi-query search, deep
/// search, MCP, and eval reuse loaded models across repeated queries.
/// Max number of indexed repositories kept resident in `SearchContext`.
///
/// Each entry holds an `Arc<SearchStores>` (BM25 reader, metadata handles,
/// mmap vector store). Profiling (`docs/adr/009-filter-scan-profiling.md`): cross-repo agent
/// sessions that round-robin 4 repos paid ~5–10 ms per switch from reopen
/// cost; a bounded LRU of 4 keeps hot repos resident while capping memory
/// (4× BM25 readers + mmap handles). LRU eviction guarantees bounded
/// resident state across arbitrary repo sets.
const SEARCH_STORES_LRU_CAPACITY: usize = 4;

pub struct SearchContext {
    provider: Option<CachedEmbeddingProvider<DynamicProvider>>,
    model_name: Option<String>,
    provider_error: Option<String>,
    backend: InferenceBackend,
    stores: Mutex<Vec<(PathBuf, Arc<SearchStores>)>>,
    /// Cross-encoder session, built on first query that actually reranks.
    ///
    /// Failed construction is cached too, so every affected search can report
    /// the reason without retrying the build.
    reranker: OnceCell<Result<Option<DynamicReranker>, String>>,
    #[cfg(test)]
    reranker_builds: std::sync::atomic::AtomicUsize,
}

impl SearchContext {
    pub async fn new(config: &VeraConfig, backend: InferenceBackend) -> Self {
        let (provider, model_name, provider_error) =
            match crate::embedding::create_dynamic_provider(config, backend).await {
                Ok((provider, model_name)) => (
                    Some(CachedEmbeddingProvider::with_namespace(
                        provider,
                        512,
                        &model_name,
                    )),
                    Some(model_name),
                    None,
                ),
                Err(err) => {
                    warn!(
                        "Failed to create embedding provider ({}), using BM25-only search",
                        err
                    );
                    (None, None, Some(err.to_string()))
                }
            };

        Self {
            provider,
            model_name,
            provider_error,
            backend,
            stores: Mutex::new(Vec::new()),
            reranker: OnceCell::new(),
            #[cfg(test)]
            reranker_builds: std::sync::atomic::AtomicUsize::new(0),
        }
    }

    pub fn bm25_only() -> Self {
        Self {
            provider: None,
            model_name: None,
            provider_error: None,
            // Unused: with no embedding provider `search` returns on the
            // BM25-only path before any reranker is resolved.
            backend: InferenceBackend::Api,
            stores: Mutex::new(Vec::new()),
            reranker: OnceCell::new(),
            #[cfg(test)]
            reranker_builds: std::sync::atomic::AtomicUsize::new(0),
        }
    }

    /// Resolve the cross-encoder for one query, or `None` when this query does
    /// not rerank or no reranker is available.
    ///
    /// The heuristic is evaluated before the build, so a query that skips
    /// reranking never touches the session.
    async fn reranker_for_query(
        &self,
        config: &VeraConfig,
        has_intent: bool,
        query: &str,
        filters: &SearchFilters,
    ) -> Result<Option<&DynamicReranker>, &str> {
        if !reranking_wanted(has_intent, query, filters) {
            return Ok(None);
        }
        self.reranker(config).await
    }

    /// Number of times the reranker build actually ran. `OnceCell` caps it at
    /// one; the interesting assertion is that it stays zero.
    #[cfg(test)]
    fn reranker_build_count(&self) -> usize {
        self.reranker_builds
            .load(std::sync::atomic::Ordering::Relaxed)
    }

    /// Resolve the cross-encoder, building it the first time one is needed.
    ///
    /// The local ONNX session is roughly a gigabyte of resident memory, and the
    /// majority of queries never reach the reranker, so it must not be built
    /// before the query is known (issue #100).
    ///
    /// Construction is cached on the context, not per query: MCP keeps one
    /// `SearchContext` for the life of the session, so a long session pays the
    /// load once. A failed build is cached the same way, deliberately. Retrying
    /// per query would turn one missing model or unusable execution provider
    /// into a multi-second stall on every subsequent search, and the failure
    /// causes are static for a process (absent asset, bad EP, unset API key).
    /// The cache is per context, so a new process or a rebuilt context retries.
    async fn reranker(&self, config: &VeraConfig) -> Result<Option<&DynamicReranker>, &str> {
        let reranker = self
            .cached_reranker(crate::retrieval::create_dynamic_reranker(
                config,
                self.backend,
            ))
            .await?;
        if reranker.is_none() && config.retrieval.reranking_enabled {
            return Err(
                "reranking is enabled but no reranker is configured; configure a reranker endpoint or run `vera config set retrieval.reranking_enabled false`",
            );
        }
        Ok(reranker)
    }

    async fn cached_reranker(
        &self,
        build: impl std::future::Future<Output = Result<Option<DynamicReranker>>>,
    ) -> Result<Option<&DynamicReranker>, &str> {
        self.reranker
            .get_or_init(|| async {
                #[cfg(test)]
                self.reranker_builds
                    .fetch_add(1, std::sync::atomic::Ordering::Relaxed);
                build.await.map_err(|err| {
                    warn!("Failed to create reranker ({})", err);
                    format!("failed to create reranker: {err}")
                })
            })
            .await
            .as_ref()
            .map(Option::as_ref)
            .map_err(String::as_str)
    }

    pub fn embedding_provider(&self) -> Option<&CachedEmbeddingProvider<DynamicProvider>> {
        self.provider.as_ref()
    }

    pub fn model_name(&self) -> Option<&str> {
        self.model_name.as_deref()
    }

    fn search_stores(&self, index_dir: &Path) -> Result<Arc<SearchStores>> {
        // Check on cache hits too: an interrupted update can leave the same inode.
        crate::indexing::freshness::ensure_index_complete(index_dir)?;
        let mut cached = self
            .stores
            .lock()
            .map_err(|_| anyhow::anyhow!("search store cache lock poisoned"))?;
        if let Some(pos) = cached.iter().position(|(dir, _)| dir == index_dir) {
            let entry = cached.remove(pos);
            // Staleness check: if the live index was rebuilt (staging swap), the
            // cached SearchStores points at the old .vera.old directory inode.
            // Its open_stamp will not match the current metadata.db stamp at the
            // live path, so we must reopen instead of serving stale BM25/metadata.
            if entry.1.is_open_stamp_current() {
                let stores = Arc::clone(&entry.1);
                cached.insert(0, entry);
                return Ok(stores);
            }
            // Stale entry: drop it and fall through to reopen.
        }

        let stores = Arc::new(SearchStores::open(index_dir)?);
        cached.insert(0, (index_dir.to_path_buf(), Arc::clone(&stores)));
        if cached.len() > SEARCH_STORES_LRU_CAPACITY {
            cached.truncate(SEARCH_STORES_LRU_CAPACITY);
        }
        Ok(stores)
    }

    #[cfg(test)]
    pub(crate) fn search_stores_cache_len(&self) -> usize {
        self.stores.lock().map(|g| g.len()).unwrap_or(0)
    }

    #[cfg(test)]
    pub(crate) fn search_stores_cache_contains(&self, index_dir: &Path) -> bool {
        self.stores
            .lock()
            .map(|g| g.iter().any(|(dir, _)| dir == index_dir))
            .unwrap_or(false)
    }

    pub async fn search(
        &self,
        index_dir: &Path,
        query: &str,
        intent: Option<&str>,
        config: &VeraConfig,
        filters: &SearchFilters,
        result_limit: usize,
    ) -> Result<(Vec<SearchResult>, SearchTimings)> {
        let total_start = Instant::now();
        // `query` (raw) drives BM25, classification, expansion and exact-match
        // augmentation. The intent prefix only enriches the semantic side
        // (embedding + reranker); sending it to BM25 makes Tantivy parse
        // `intent:` as a non-existent field and fail. See issue #20.
        let vector_query = build_query_with_intent(query, intent);
        // True when an intent prefix was actually applied (non-empty intent).
        let has_intent = matches!(vector_query, std::borrow::Cow::Owned(_));
        let fetch_limit = compute_fetch_limit_with_config(query, filters, result_limit, config);
        let stores = self.search_stores(index_dir)?;

        let Some(provider) = self.provider.as_ref() else {
            if let Some(error) = self.provider_error.as_deref() {
                warn!(
                    "embedding provider unavailable ({}), using BM25-only search",
                    error
                );
            }
            return run_bm25_only(
                query,
                filters,
                fetch_limit,
                result_limit,
                total_start,
                &stores,
                config,
            );
        };

        let mut stored_dim = config.embedding.max_stored_dim;

        // Profiling: docs/adr/009-filter-scan-profiling.md — three `get_index_meta` reads per
        // query cost ~0.45 ms warm p50, served from stamp-guarded cache.
        // Propagate cache errors to BM25-only rather than silently skipping
        // compatibility checks (vector space mismatch would otherwise be missed).
        let index_meta = match stores.cached_index_meta() {
            Ok(meta) => Some(meta),
            Err(err) => {
                warn!(
                    "failed to read index meta ({}), using BM25-only search",
                    err
                );
                return run_bm25_only(
                    query,
                    filters,
                    fetch_limit,
                    result_limit,
                    total_start,
                    &stores,
                    config,
                );
            }
        };
        if let Some((Some(s_model), Some(s_dim), s_prefix)) = index_meta {
            if let Some(model_name) = self.model_name.as_deref()
                && !crate::config::model_names_match_with_aliases(
                    &s_model,
                    model_name,
                    &config.embedding.model_aliases,
                )
            {
                warn!(
                    "Index model '{}' does not match active model '{}'; using BM25-only search",
                    s_model, model_name
                );
                return run_bm25_only(
                    query,
                    filters,
                    fetch_limit,
                    result_limit,
                    total_start,
                    &stores,
                    config,
                );
            }
            // A changed document prefix means the stored vectors live in a
            // different vector space. Indexes written before this guard have
            // no stored prefix, and their documents were never prefixed.
            let active_prefix = provider.document_prefix_identity();
            if s_prefix.as_deref().unwrap_or("") != active_prefix {
                warn!(
                    "Index document prefix '{}' does not match active prefix '{}'; using BM25-only search (re-index to restore vector search)",
                    s_prefix.as_deref().unwrap_or(""),
                    active_prefix
                );
                return run_bm25_only(
                    query,
                    filters,
                    fetch_limit,
                    result_limit,
                    total_start,
                    &stores,
                    config,
                );
            }
            if let Ok(dim) = s_dim.parse::<usize>() {
                if let Some(provider_dim) = provider.expected_dim()
                    && provider_dim < dim
                {
                    warn!(
                        "Index dimension {} exceeds provider dimension {}; using BM25-only search",
                        dim, provider_dim
                    );
                    return run_bm25_only(
                        query,
                        filters,
                        fetch_limit,
                        result_limit,
                        total_start,
                        &stores,
                        config,
                    );
                }
                stored_dim = dim;
            }
        }

        // Decide before building: only a query that will actually be reranked
        // pays for the cross-encoder session. An explicit intent is a semantic
        // signal only the reranker/embedding side can use, so it forces
        // reranking on. A reranker that is unavailable degrades to plain hybrid
        // search, as it did when the build happened up front.
        let reranker = self
            .reranker_for_query(config, has_intent, query, filters)
            .await;
        let reranker_enabled = matches!(reranker, Ok(Some(_)));

        // Classify query to adapt fusion parameters.
        let query_type = classify_query(query);
        let query_params = params_for_query_type(query_type);
        let rrf_k = query_params.rrf_k;
        let vector_candidates = effective_vector_candidates(fetch_limit, query_params);
        let rerank_candidates =
            effective_rerank_candidates(config.retrieval.rerank_candidates, result_limit);

        let ranking_stage = if reranker_enabled {
            RankingStage::PostRerank
        } else {
            RankingStage::Initial
        };

        let filter_flag = config.retrieval.vector_filter_during_scan_enabled();
        let (results, hybrid_timings) = if let Ok(Some(reranker)) = reranker {
            crate::retrieval::hybrid::search_hybrid_reranked_with_stores_and_flag(
                index_dir,
                provider,
                reranker,
                query,
                vector_query.as_ref(),
                filters,
                fetch_limit,
                result_limit,
                rrf_k,
                stored_dim,
                rerank_candidates,
                vector_candidates,
                Arc::clone(&stores),
                filter_flag,
            )
            .await?
        } else {
            crate::retrieval::hybrid::search_hybrid_with_stores_and_flag(
                index_dir,
                provider,
                query,
                vector_query.as_ref(),
                filters,
                fetch_limit,
                rrf_k,
                stored_dim,
                vector_candidates,
                Arc::clone(&stores),
                filter_flag,
            )
            .await?
        };

        let mut timings = SearchTimings::from(hybrid_timings);
        // Like the runtime path, empty or already-small candidate pools do not
        // need reranking even when construction was unavailable.
        if results.len() > result_limit
            && let Err(reason) = reranker
        {
            timings.rerank_outcome = RerankOutcome::fallback(reason.to_string());
        }

        let aug_start = Instant::now();
        let indexed_files = stores.indexed_files()?;
        let metadata_store = stores
            .bm25_metadata
            .lock()
            .map_err(|_| anyhow::anyhow!("BM25 metadata store lock poisoned"))?;
        let results = augment_exact_match_candidates_with_store_and_config(
            &metadata_store,
            &indexed_files,
            query,
            results,
            ranking_stage,
            filters,
            config,
        )?;
        timings.augmentation = Some(aug_start.elapsed());

        timings.total = Some(total_start.elapsed());
        let final_results = apply_filters(results, filters, result_limit);
        Ok((final_results, timings))
    }
}

/// Execute a search against the index at `index_dir`.
///
/// Attempts hybrid search (BM25 + vector + optional reranking). Falls
/// back to BM25-only when embedding API is unavailable.
pub fn execute_search(
    index_dir: &Path,
    query: &str,
    intent: Option<&str>,
    config: &VeraConfig,
    filters: &SearchFilters,
    result_limit: usize,
    backend: InferenceBackend,
) -> Result<(Vec<SearchResult>, SearchTimings)> {
    let rt = tokio::runtime::Runtime::new()?;
    let context = rt.block_on(SearchContext::new(config, backend));
    rt.block_on(context.search(index_dir, query, intent, config, filters, result_limit))
}

/// Build the semantic query text used for embedding and reranking.
///
/// When an `--intent` is supplied it is prefixed as `intent: <intent> | <query>`
/// (intent whitespace collapsed) to steer the embedding model. The raw `query`
/// is returned unchanged when no usable intent is present. This prefixed form
/// must never reach BM25: Tantivy's `QueryParser` treats `intent:` as a field
/// query and there is no such field. See issue #20.
pub(crate) fn build_query_with_intent<'a>(
    query: &'a str,
    intent: Option<&str>,
) -> std::borrow::Cow<'a, str> {
    let intent = intent
        .map(|value| value.split_whitespace().collect::<Vec<_>>().join(" "))
        .filter(|value| !value.is_empty());
    match intent {
        // Only allocate when an intent prefix is actually applied; otherwise
        // borrow the raw query.
        Some(intent) => std::borrow::Cow::Owned(format!("intent: {intent} | {query}")),
        None => std::borrow::Cow::Borrowed(query),
    }
}

/// Compute how many candidates to keep through fusion before final truncation.
///
/// Broad natural-language queries need a larger pool even without explicit
/// filters so deterministic ranking can surface structural chunks that raw RRF
/// scores placed outside the requested result window. Gated by the
/// `ranking_recall_pool_expansion` signal (issue #196) so ablations can
/// measure its contribution without changing other ranking logic.
#[cfg(test)]
fn compute_fetch_limit(query: &str, filters: &SearchFilters, result_limit: usize) -> usize {
    compute_fetch_limit_with_config(query, filters, result_limit, &VeraConfig::default())
}

pub(crate) fn compute_fetch_limit_with_config(
    query: &str,
    filters: &SearchFilters,
    result_limit: usize,
    config: &VeraConfig,
) -> usize {
    let mut fetch_limit = if filters.is_empty() {
        result_limit
    } else {
        result_limit.saturating_mul(3).max(result_limit + 20)
    };

    // Path globs are applied post-retrieval, so we need a much larger pool
    // to ensure enough matching files survive filtering.
    if !filters.path_glob.is_empty() {
        fetch_limit = fetch_limit.max(result_limit.saturating_mul(10).max(result_limit + 100));
    }

    if filters.exact_paths.is_some() {
        fetch_limit = fetch_limit.max(result_limit.saturating_mul(12).max(result_limit + 200));
    }

    // Preserve filter-driven overfetch when recall expansion is disabled.
    if !config.retrieval.ranking_recall_pool_expansion_enabled() {
        return fetch_limit;
    }

    if needs_structural_overfetch(query, filters) {
        fetch_limit = fetch_limit.max(result_limit.saturating_mul(8).max(result_limit + 140));
    } else if matches!(classify_query(query), QueryType::NaturalLanguage) {
        fetch_limit = fetch_limit.max(result_limit.saturating_mul(3).max(result_limit + 40));
    }

    fetch_limit
}

fn needs_structural_overfetch(query: &str, filters: &SearchFilters) -> bool {
    matches!(classify_query(query), QueryType::NaturalLanguage)
        && query.split_whitespace().count() >= 4
        && filters.path_glob.is_empty()
        && filters.exact_paths.is_none()
        && filters.symbol_type.is_none()
        && !is_path_weighted_query(query)
}

fn effective_vector_candidates(
    fetch_limit: usize,
    query_params: crate::retrieval::query_classifier::QueryParams,
) -> usize {
    compute_vector_candidates(fetch_limit, query_params.vector_candidate_multiplier)
}

fn effective_rerank_candidates(configured: usize, result_limit: usize) -> usize {
    configured.max(result_limit)
}

/// Decide whether this query wants the cross-encoder reranker.
///
/// Skip heuristics (short identifier / path-weighted / exact-path or
/// symbol-type filtered lookups) are based on the raw query. But when the user
/// supplies an `--intent`, they are asking for semantic ranking, so the
/// reranker must run even for short raw queries — otherwise the intent-enriched
/// query would never reach the cross-encoder. See issue #20.
///
/// This answers only "does this query want reranking", never "is a reranker
/// available": it is what gates the session build, so it must not need one.
fn reranking_wanted(has_intent: bool, query: &str, filters: &SearchFilters) -> bool {
    has_intent || !should_skip_reranking(query, filters)
}

fn should_skip_reranking(query: &str, filters: &SearchFilters) -> bool {
    let word_count = query.split_whitespace().count();
    filters.exact_paths.is_some()
        || filters.symbol_type.is_some()
        || is_path_weighted_query(query)
        || (matches!(classify_query(query), QueryType::Identifier) && word_count <= 2)
}

fn run_bm25_only(
    query: &str,
    filters: &SearchFilters,
    fetch_limit: usize,
    result_limit: usize,
    total_start: Instant,
    stores: &Arc<SearchStores>,
    config: &VeraConfig,
) -> Result<(Vec<SearchResult>, SearchTimings)> {
    let bm25_start = Instant::now();
    let metadata_store = stores
        .bm25_metadata
        .lock()
        .map_err(|_| anyhow::anyhow!("BM25 metadata store lock poisoned"))?;
    let results = search_bm25_with_stores_and_filters(
        &stores.bm25,
        &metadata_store,
        query,
        filters,
        fetch_limit,
    )?;
    let bm25_elapsed = bm25_start.elapsed();
    let aug_start = Instant::now();
    let indexed_files = stores.indexed_files()?;
    let results = augment_exact_match_candidates_with_store_and_config(
        &metadata_store,
        &indexed_files,
        query,
        results,
        RankingStage::Initial,
        filters,
        config,
    )?;
    let timings = SearchTimings {
        bm25: Some(bm25_elapsed),
        augmentation: Some(aug_start.elapsed()),
        total: Some(total_start.elapsed()),
        ..Default::default()
    };
    Ok((apply_filters(results, filters, result_limit), timings))
}

#[cfg(test)]
mod tests {
    use super::*;
    use crate::retrieval::exact_matches::augment_exact_match_candidates;
    use crate::storage::bm25::{Bm25Document, Bm25Index};
    use crate::storage::metadata::MetadataStore;
    use crate::test_env::run_env_test;
    use crate::types::Language;
    use crate::types::{Chunk, SymbolType};
    use tempfile::tempdir;

    fn run_reranker_unavailability_probe(failed_build: bool) {
        let output = std::process::Command::new(std::env::current_exe().unwrap())
            .args([
                "retrieval::search_service::tests::reranker_unavailability_probe",
                "--exact",
                "--ignored",
                "--nocapture",
            ])
            .env_clear()
            .env("PATH", std::env::var_os("PATH").unwrap_or_default())
            .env("TMPDIR", std::env::temp_dir())
            .env("EMBEDDING_MODEL_BASE_URL", "http://127.0.0.1:0/v1")
            .env("EMBEDDING_MODEL_ID", "mock-model")
            .env("EMBEDDING_MODEL_API_KEY", "test-key")
            .env("VERA_TEST_FAILED_BUILD", failed_build.to_string())
            .output()
            .unwrap();
        assert!(
            output.status.success(),
            "{}\n{}",
            String::from_utf8_lossy(&output.stdout),
            String::from_utf8_lossy(&output.stderr)
        );
        let stderr = String::from_utf8_lossy(&output.stderr);
        assert_eq!(
            stderr.matches("Warning: reranker unavailable (").count(),
            2,
            "{stderr}"
        );
    }

    #[test]
    fn construction_failure_warns_on_every_search_and_builds_once() {
        run_reranker_unavailability_probe(true);
    }

    #[test]
    fn enabled_without_reranker_falls_back_and_disabled_does_not() {
        run_reranker_unavailability_probe(false);
    }

    #[tokio::test]
    #[ignore = "driven by the reranker unavailability tests"]
    async fn reranker_unavailability_probe() {
        use crate::embedding::test_helpers::MockProvider;
        let dir = tempdir().unwrap();
        for i in 0..8 {
            std::fs::write(dir.path().join(format!("auth_{i}.rs")), format!(
                "/// Authentication handles user requests.\npub fn authenticate_{i}() -> usize {{ {i} }}\n"
            )).unwrap();
        }
        let mut config = VeraConfig::default();
        config.embedding.max_retries = 0;
        config.embedding.timeout_secs = 1;
        config.retrieval.reranking_enabled = true;
        crate::indexing::index_repository(dir.path(), &MockProvider::new(8), &config, "mock-model")
            .await
            .unwrap();
        let index_dir = dir.path().join(".vera");
        let context = SearchContext::new(&config, InferenceBackend::Api).await;
        let failed_build = std::env::var("VERA_TEST_FAILED_BUILD").unwrap() == "true";
        if failed_build {
            assert_eq!(
                context
                    .cached_reranker(async { Err(anyhow::anyhow!("mock construction failure")) })
                    .await
                    .err(),
                Some("failed to create reranker: mock construction failure"),
            );
        }
        let query = "how does authentication handle user requests";
        for _ in 0..2 {
            let (results, timings) = context
                .search(
                    &index_dir,
                    query,
                    None,
                    &config,
                    &SearchFilters::default(),
                    1,
                )
                .await
                .unwrap();
            assert!(!results.is_empty());
            let RerankOutcome::Fallback(reason) = timings.rerank_outcome else {
                panic!("expected fallback")
            };
            if failed_build {
                assert_eq!(
                    reason,
                    "failed to create reranker: mock construction failure"
                );
            } else {
                assert!(reason.starts_with("reranking is enabled but no reranker is configured"));
                assert!(reason.contains("vera config set retrieval.reranking_enabled false"));
            }
        }
        assert_eq!(context.reranker_build_count(), 1);
        for (filters, limit) in [
            (SearchFilters::default(), 100),
            (
                SearchFilters {
                    path_glob: vec!["missing/**".into()],
                    ..Default::default()
                },
                1,
            ),
        ] {
            let (_, timings) = context
                .search(&index_dir, query, None, &config, &filters, limit)
                .await
                .unwrap();
            assert_eq!(timings.rerank_outcome, RerankOutcome::NotAttempted);
        }
        config.retrieval.reranking_enabled = false;
        let disabled = SearchContext::new(&config, InferenceBackend::Api).await;
        let (_, timings) = disabled
            .search(
                &index_dir,
                query,
                None,
                &config,
                &SearchFilters::default(),
                1,
            )
            .await
            .unwrap();
        assert_eq!(timings.rerank_outcome, RerankOutcome::NotAttempted);
    }

    #[test]
    fn test_dimension_mismatch_and_inference() {
        run_env_test(
            "retrieval::search_service::tests::test_dimension_mismatch_and_inference_probe",
            &[
                ("EMBEDDING_MODEL_BASE_URL", Some("http://127.0.0.1:0")),
                ("EMBEDDING_MODEL_ID", Some("dummy-api-model")),
                ("EMBEDDING_MODEL_API_KEY", Some("dummy-key")),
            ],
        );
    }

    #[test]
    #[ignore = "driven by test_dimension_mismatch_and_inference"]
    fn test_dimension_mismatch_and_inference_probe() {
        crate::init_tls();
        let dir = tempdir().unwrap();
        let index_dir = dir.path();

        let metadata_path = index_dir.join("metadata.db");
        let store = MetadataStore::open(&metadata_path).unwrap();

        // 1. Test dimension mismatch (requires local model so provider_dim is Some(768))
        store
            .set_index_meta("model_name", "jina-embeddings-v5-text-nano-retrieval")
            .unwrap();
        store.set_index_meta("embedding_dim", "1024").unwrap(); // Mismatch: 1024 vs 768

        let config = VeraConfig::default();
        let filters = SearchFilters::default();

        // This attempts local provider creation first, then falls back to BM25 when possible.
        // In this synthetic test fixture the BM25 index is absent, so either path may surface.
        {
            let res = execute_search(
                index_dir,
                "test",
                None,
                &config,
                &filters,
                10,
                crate::config::InferenceBackend::OnnxJina(
                    crate::config::OnnxExecutionProvider::Cpu,
                ),
            );
            if let Err(err) = res {
                let err_msg = err.to_string();
                assert!(
                    err_msg.contains("tantivy")
                        || err_msg.contains("Failed to initialize local embedding provider")
                        || err_msg.contains("No such file")
                        || err_msg.contains("not found"),
                    "{}",
                    err_msg
                );
            }
        }

        // 2. Test metadata-dimension inference path (API provider returns None for expected_dim)
        // The dummy provider credentials are already set by the guard above.
        store
            .set_index_meta("model_name", "dummy-api-model")
            .unwrap();
        store.set_index_meta("embedding_dim", "123").unwrap();

        // Calling execute_search with is_local = false
        // It will pass the metadata check (model_name matches), skip mismatch check (expected_dim is None),
        // infer stored_dim = 123, and proceed to search.
        // Since the index is empty, it will return Ok([]) without making network calls.
        let res = execute_search(
            index_dir,
            "test",
            None,
            &config,
            &filters,
            10,
            crate::config::InferenceBackend::Api,
        );
        assert!(res.is_ok(), "Expected Ok but got {:?}", res);
    }

    #[test]
    fn model_metadata_mismatch_falls_back_to_bm25() {
        run_env_test(
            "retrieval::search_service::tests::model_metadata_mismatch_falls_back_to_bm25_probe",
            &[
                ("EMBEDDING_MODEL_BASE_URL", Some("http://127.0.0.1:0")),
                ("EMBEDDING_MODEL_ID", Some("active-api-model")),
                ("EMBEDDING_MODEL_API_KEY", Some("dummy-key")),
            ],
        );
    }

    #[test]
    #[ignore = "driven by model_metadata_mismatch_falls_back_to_bm25"]
    fn model_metadata_mismatch_falls_back_to_bm25_probe() {
        crate::init_tls();
        let dir = tempdir().unwrap();
        let index_dir = dir.path();

        let store = MetadataStore::open(&index_dir.join("metadata.db")).unwrap();
        store
            .insert_chunks(&[Chunk {
                id: "auth:0".to_string(),
                file_path: "src/auth.rs".to_string(),
                line_start: 1,
                line_end: 4,
                content: "pub fn authenticate_user() -> bool { true }".to_string(),
                language: Language::Rust,
                symbol_type: Some(SymbolType::Function),
                symbol_name: Some("authenticate_user".to_string()),
                part_index: None,
            }])
            .unwrap();
        store.set_index_meta("model_name", "indexed-model").unwrap();
        store.set_index_meta("embedding_dim", "64").unwrap();

        let bm25 = Bm25Index::open(&index_dir.join("bm25")).unwrap();
        bm25.insert_batch(&[Bm25Document {
            chunk_id: "auth:0",
            file_path: "src/auth.rs",
            content: "pub fn authenticate_user() -> bool { true }",
            symbol_name: Some("authenticate_user"),
            language: "rust",
        }])
        .unwrap();

        let mut config = VeraConfig::default();
        config.embedding.timeout_secs = 1;
        config.embedding.max_retries = 0;
        let filters = SearchFilters::default();
        let rt = tokio::runtime::Runtime::new().unwrap();
        let context = rt.block_on(SearchContext::new(
            &config,
            crate::config::InferenceBackend::Api,
        ));

        let (results, timings) = rt
            .block_on(context.search(index_dir, "authenticate user", None, &config, &filters, 10))
            .unwrap();

        assert_eq!(results[0].file_path, "src/auth.rs");
        assert!(timings.bm25.is_some());
        assert!(timings.vector.is_none());
    }

    #[test]
    fn document_prefix_mismatch_falls_back_to_bm25() {
        run_env_test(
            "retrieval::search_service::tests::document_prefix_mismatch_falls_back_to_bm25_probe",
            &[
                ("EMBEDDING_MODEL_BASE_URL", Some("http://127.0.0.1:0")),
                ("EMBEDDING_MODEL_ID", Some("indexed-model")),
                ("EMBEDDING_MODEL_API_KEY", Some("dummy-key")),
            ],
        );
    }

    #[test]
    #[ignore = "driven by document_prefix_mismatch_falls_back_to_bm25"]
    fn document_prefix_mismatch_falls_back_to_bm25_probe() {
        crate::init_tls();
        let dir = tempdir().unwrap();
        let index_dir = dir.path();

        let store = MetadataStore::open(&index_dir.join("metadata.db")).unwrap();
        store
            .insert_chunks(&[Chunk {
                id: "auth:0".to_string(),
                file_path: "src/auth.rs".to_string(),
                line_start: 1,
                line_end: 4,
                content: "pub fn authenticate_user() -> bool { true }".to_string(),
                language: Language::Rust,
                symbol_type: Some(SymbolType::Function),
                symbol_name: Some("authenticate_user".to_string()),
                part_index: None,
            }])
            .unwrap();
        store.set_index_meta("model_name", "indexed-model").unwrap();
        store.set_index_meta("embedding_dim", "64").unwrap();
        // The index was built with a document prefix, but the active provider
        // configuration has none: the stored vectors are in another space.
        store
            .set_index_meta("document_prefix", "passage: ")
            .unwrap();

        let bm25 = Bm25Index::open(&index_dir.join("bm25")).unwrap();
        bm25.insert_batch(&[Bm25Document {
            chunk_id: "auth:0",
            file_path: "src/auth.rs",
            content: "pub fn authenticate_user() -> bool { true }",
            symbol_name: Some("authenticate_user"),
            language: "rust",
        }])
        .unwrap();

        let mut config = VeraConfig::default();
        config.embedding.timeout_secs = 1;
        config.embedding.max_retries = 0;
        let filters = SearchFilters::default();
        let rt = tokio::runtime::Runtime::new().unwrap();
        let context = rt.block_on(SearchContext::new(
            &config,
            crate::config::InferenceBackend::Api,
        ));

        let (results, timings) = rt
            .block_on(context.search(index_dir, "authenticate user", None, &config, &filters, 10))
            .unwrap();

        assert_eq!(results[0].file_path, "src/auth.rs");
        assert!(timings.bm25.is_some());
        assert!(timings.vector.is_none());
    }

    #[test]
    fn bm25_only_search_fills_path_scoped_results_from_deeper_pool() {
        let dir = tempdir().unwrap();
        let index_dir = dir.path();
        let metadata_store = MetadataStore::open(&index_dir.join("metadata.db")).unwrap();
        let bm25 = Bm25Index::open(&index_dir.join("bm25")).unwrap();

        let mut chunks = Vec::new();
        for i in 0..160 {
            chunks.push(Chunk {
                id: format!("noise:{i}"),
                file_path: format!("other/dependency_injection_work_{i}.py"),
                line_start: 1,
                line_end: 4,
                content:
                    "def dependency_injection_work():\n    dependency injection work dependency injection work"
                        .to_string(),
                language: Language::Python,
                symbol_type: Some(SymbolType::Function),
                symbol_name: Some("dependency_injection_work".to_string()),
                part_index: None,
            });
        }
        chunks.push(Chunk {
            id: "fastapi:dependency".to_string(),
            file_path: "fastapi/dependencies/utils.py".to_string(),
            line_start: 42,
            line_end: 55,
            content: "def solve_dependencies():\n    \"\"\"Resolve dependency injection for request handlers.\"\"\"\n    return values"
                .to_string(),
            language: Language::Python,
            symbol_type: Some(SymbolType::Function),
            symbol_name: Some("solve_dependencies".to_string()),
            part_index: None,
        });

        metadata_store.insert_chunks(&chunks).unwrap();
        let lang_strings: Vec<String> = chunks.iter().map(|c| c.language.to_string()).collect();
        let docs: Vec<Bm25Document<'_>> = chunks
            .iter()
            .zip(lang_strings.iter())
            .map(|(chunk, language)| Bm25Document {
                chunk_id: &chunk.id,
                file_path: &chunk.file_path,
                content: &chunk.content,
                symbol_name: chunk.symbol_name.as_deref(),
                language,
            })
            .collect();
        bm25.insert_batch(&docs).unwrap();

        let filters = SearchFilters {
            path_glob: vec!["fastapi/**".to_string()],
            ..Default::default()
        };
        let rt = tokio::runtime::Runtime::new().unwrap();
        let context = SearchContext::bm25_only();

        let (results, timings) = rt
            .block_on(context.search(
                index_dir,
                "how does dependency injection work",
                None,
                &VeraConfig::default(),
                &filters,
                5,
            ))
            .unwrap();

        assert_eq!(results.len(), 1);
        assert_eq!(results[0].file_path, "fastapi/dependencies/utils.py");
        assert!(timings.bm25.is_some());
        // The query above is one `reranking_wanted` accepts, so this pins the
        // invariant `bm25_only`'s placeholder backend rests on: `search` returns
        // on the BM25-only path before any reranker is resolved.
        assert_eq!(
            context.reranker_build_count(),
            0,
            "a context with no embedding provider must never construct a reranker"
        );
    }

    #[test]
    fn build_query_with_intent_formats_and_normalizes() {
        // No intent: raw query borrowed unchanged (this is what BM25 receives).
        let none = build_query_with_intent("test query", None);
        assert_eq!(none.as_ref(), "test query");
        assert!(matches!(none, std::borrow::Cow::Borrowed(_)));
        // Empty / whitespace-only intent collapses to no prefix (still borrowed).
        let empty = build_query_with_intent("test query", Some("   "));
        assert_eq!(empty.as_ref(), "test query");
        assert!(matches!(empty, std::borrow::Cow::Borrowed(_)));
        // Intent present: owned prefixed form with whitespace collapsed.
        let some = build_query_with_intent("test query", Some("find  auth\n handlers"));
        assert_eq!(some.as_ref(), "intent: find auth handlers | test query");
        assert!(matches!(some, std::borrow::Cow::Owned(_)));
    }

    #[test]
    fn reranking_runs_for_intent_searches_with_short_queries() {
        let filters = SearchFilters::default();
        // A short identifier query alone is skipped by the rerank heuristic.
        assert!(should_skip_reranking("authenticate", &filters));
        // Without intent that means reranking is off...
        assert!(!reranking_wanted(false, "authenticate", &filters));
        // ...but an intent forces the cross-encoder to run so it sees the
        // intent-enriched query (issue #20 regression guard).
        assert!(reranking_wanted(true, "authenticate", &filters));
        // Natural-language query without intent still reranks normally.
        assert!(reranking_wanted(false, "how does auth work", &filters));
    }

    /// The cross-encoder session must not be built for queries that skip
    /// reranking (issue #100), and must be built once, not per query, for those
    /// that need it.
    ///
    /// The result sets are identical either way, so this asserts construction
    /// directly via the build counter rather than any search output.
    #[test]
    fn reranker_is_built_only_for_queries_that_rerank() {
        run_env_test(
            "retrieval::search_service::tests::reranker_is_built_only_for_queries_that_rerank_probe",
            &[
                ("EMBEDDING_MODEL_BASE_URL", Some("http://127.0.0.1:0")),
                ("EMBEDDING_MODEL_ID", Some("dummy-api-model")),
                ("EMBEDDING_MODEL_API_KEY", Some("dummy-key")),
                ("RERANKER_MODEL_BASE_URL", Some("http://127.0.0.1:0")),
                ("RERANKER_MODEL_ID", Some("dummy-reranker-model")),
                ("RERANKER_MODEL_API_KEY", Some("dummy-key")),
            ],
        );
    }

    #[tokio::test]
    #[ignore = "driven by reranker_is_built_only_for_queries_that_rerank"]
    async fn reranker_is_built_only_for_queries_that_rerank_probe() {
        crate::init_tls();
        let mut config = VeraConfig::default();
        config.retrieval.reranking_enabled = true;
        let filters = SearchFilters::default();
        let context = SearchContext::new(&config, crate::config::InferenceBackend::Api).await;

        // Nothing is built up front, which is the whole point.
        assert_eq!(context.reranker_build_count(), 0);

        // Short identifier query: skipped by the heuristic, so no session.
        assert!(!reranking_wanted(false, "Bm25Index", &filters));
        assert!(
            context
                .reranker_for_query(&config, false, "Bm25Index", &filters)
                .await
                .unwrap()
                .is_none()
        );
        assert_eq!(
            context.reranker_build_count(),
            0,
            "a query that skips reranking must not construct the reranker"
        );

        // Natural-language query: needs the cross-encoder, so build it now.
        assert!(
            context
                .reranker_for_query(
                    &config,
                    false,
                    "how are embeddings batched during indexing",
                    &filters
                )
                .await
                .unwrap()
                .is_some()
        );
        assert_eq!(context.reranker_build_count(), 1);

        // A second reranking query reuses the cached session: laziness is per
        // context, so a long MCP session does not pay repeatedly.
        assert!(
            context
                .reranker_for_query(&config, false, "how does auth work", &filters)
                .await
                .unwrap()
                .is_some()
        );
        assert_eq!(context.reranker_build_count(), 1);
    }

    #[test]
    fn path_glob_filters_do_not_skip_reranking() {
        let filters = SearchFilters {
            path_glob: vec!["crates/vera-core/**".to_string()],
            ..Default::default()
        };

        assert!(!should_skip_reranking(
            "how does dependency injection work",
            &filters
        ));
    }

    #[test]
    fn rerank_candidate_depth_is_independent_of_fetch_depth() {
        assert_eq!(effective_rerank_candidates(20, 5), 20);
        assert_eq!(
            effective_rerank_candidates(4, 5),
            5,
            "reranking must cover enough candidates to return the requested result count"
        );

        // Vector candidates use query_params multiplier without inflation
        let nl_params =
            params_for_query_type(crate::retrieval::query_classifier::QueryType::NaturalLanguage);
        let vc = effective_vector_candidates(10, nl_params);
        assert!(vc >= 50); // at least the minimum from compute_vector_candidates
    }

    #[test]
    fn broad_nl_queries_overfetch_before_ranking() {
        let filters = SearchFilters::default();

        assert_eq!(compute_fetch_limit("Config", &filters, 20), 20);
        assert_eq!(
            compute_fetch_limit("file type detection and filtering", &filters, 20),
            160
        );
        assert_eq!(
            compute_fetch_limit(
                "how are HTTP errors handled and returned to clients",
                &filters,
                5
            ),
            145
        );
    }

    #[test]
    fn recall_pool_expansion_is_toggleable() {
        let filters = SearchFilters::default();
        // NL queries overfetch when expansion enabled; identifier queries do not.
        let enabled = VeraConfig::default();
        assert!(enabled.retrieval.ranking_recall_pool_expansion_enabled());

        // With expansion on, broad NL queries get inflated fetch limits
        let expanded = compute_fetch_limit_with_config(
            "file type detection and filtering",
            &filters,
            20,
            &enabled,
        );
        assert_eq!(expanded, 160);

        // With expansion off, same query must stay at base limit (filters empty => result_limit)
        let mut disabled = VeraConfig::default();
        disabled.retrieval.ranking_recall_pool_expansion = false;
        let collapsed = compute_fetch_limit_with_config(
            "file type detection and filtering",
            &filters,
            20,
            &disabled,
        );
        assert_eq!(
            collapsed, 20,
            "with recall expansion disabled, NL structural overfetch must not apply"
        );

        // Filter-driven expansion still applies even when recall expansion is off
        let filtered = SearchFilters {
            path_glob: vec!["src/**".to_string()],
            ..Default::default()
        };
        let filtered_collapsed = compute_fetch_limit_with_config(
            "file type detection and filtering",
            &filtered,
            20,
            &disabled,
        );
        assert!(
            filtered_collapsed >= 200,
            "path_glob inflation must survive even when recall expansion is off, got {filtered_collapsed}"
        );

        // Identifier query never inflates, regardless of flag
        let ident_expanded = compute_fetch_limit_with_config("Config", &filters, 20, &enabled);
        let ident_collapsed = compute_fetch_limit_with_config("Config", &filters, 20, &disabled);
        assert_eq!(ident_expanded, 20);
        assert_eq!(ident_collapsed, 20);
    }

    #[test]
    fn exact_identifier_queries_skip_reranking() {
        assert!(should_skip_reranking("Config", &SearchFilters::default()));
        assert!(should_skip_reranking(
            "src/config.ts",
            &SearchFilters::default()
        ));
        assert!(!should_skip_reranking(
            "how are HTTP errors handled",
            &SearchFilters::default()
        ));
    }

    #[test]
    fn exact_identifier_lookup_finds_matching_symbol() {
        let dir = tempdir().unwrap();
        let metadata_path = dir.path().join("metadata.db");
        let store = MetadataStore::open(&metadata_path).unwrap();
        store
            .insert_chunks(&[Chunk {
                id: "sink:0".to_string(),
                file_path: "crates/searcher/src/sink.rs".to_string(),
                line_start: 102,
                line_end: 223,
                content: "pub trait Sink {}".to_string(),
                language: Language::Rust,
                symbol_type: Some(SymbolType::Trait),
                symbol_name: Some("Sink".to_string()),
                part_index: None,
            }])
            .unwrap();

        let augmented = augment_exact_match_candidates(
            dir.path(),
            "Sink trait and its implementations",
            Vec::new(),
            RankingStage::Initial,
            &SearchFilters::default(),
        )
        .unwrap();

        assert!(
            augmented
                .iter()
                .any(|result| result.symbol_name.as_deref() == Some("Sink"))
        );
    }

    #[test]
    fn exact_identifier_prefers_public_type_definition() {
        let dir = tempdir().unwrap();
        let metadata_path = dir.path().join("metadata.db");
        let store = MetadataStore::open(&metadata_path).unwrap();
        store
            .insert_chunks(&[
                Chunk {
                    id: "config:0".to_string(),
                    file_path: "crates/core/search.rs".to_string(),
                    line_start: 19,
                    line_end: 25,
                    content: "struct Config {\n    search_zip: bool,\n}".to_string(),
                    language: Language::Rust,
                    symbol_type: Some(SymbolType::Struct),
                    symbol_name: Some("Config".to_string()),
                    part_index: None,
                },
                Chunk {
                    id: "config:1".to_string(),
                    file_path: "crates/regex/src/config.rs".to_string(),
                    line_start: 25,
                    line_end: 43,
                    content: "pub(crate) struct Config {\n    pub(crate) multi_line: bool,\n}".to_string(),
                    language: Language::Rust,
                    symbol_type: Some(SymbolType::Struct),
                    symbol_name: Some("Config".to_string()),
                    part_index: None,
                },
                Chunk {
                    id: "config:2".to_string(),
                    file_path: "crates/searcher/src/searcher/mod.rs".to_string(),
                    line_start: 151,
                    line_end: 185,
                    content: "pub struct Config {\n    line_term: LineTerminator,\n    multi_line: bool,\n}".to_string(),
                    language: Language::Rust,
                    symbol_type: Some(SymbolType::Struct),
                    symbol_name: Some("Config".to_string()),
                    part_index: None,
                },
            ])
            .unwrap();

        let augmented = augment_exact_match_candidates(
            dir.path(),
            "Config",
            Vec::new(),
            RankingStage::Initial,
            &SearchFilters::default(),
        )
        .unwrap();

        assert_eq!(
            augmented[0].file_path,
            "crates/searcher/src/searcher/mod.rs"
        );
    }

    #[test]
    fn multi_query_exact_matches_are_promoted_after_fusion() {
        let dir = tempdir().unwrap();
        let metadata_path = dir.path().join("metadata.db");
        let store = MetadataStore::open(&metadata_path).unwrap();
        store
            .insert_chunks(&[
                Chunk {
                    id: "kimi:0".to_string(),
                    file_path: "backend/crates/omnigate-auth/src/kimi.rs".to_string(),
                    line_start: 265,
                    line_end: 275,
                    content: "pub fn persist_kimi_auth_record() {}".to_string(),
                    language: Language::Rust,
                    symbol_type: Some(SymbolType::Function),
                    symbol_name: Some("persist_kimi_auth_record".to_string()),
                    part_index: None,
                },
                Chunk {
                    id: "factory:0".to_string(),
                    file_path: "backend/crates/omnigate-auth/src/factory.rs".to_string(),
                    line_start: 286,
                    line_end: 296,
                    content: "pub fn persist_factory_auth_record() {}".to_string(),
                    language: Language::Rust,
                    symbol_type: Some(SymbolType::Function),
                    symbol_name: Some("persist_factory_auth_record".to_string()),
                    part_index: None,
                },
                Chunk {
                    id: "lib:0".to_string(),
                    file_path: "backend/crates/omnigate-auth/src/lib.rs".to_string(),
                    line_start: 10,
                    line_end: 40,
                    content: "pub use crate::kimi::persist_kimi_auth_record;".to_string(),
                    language: Language::Rust,
                    symbol_type: Some(SymbolType::Module),
                    symbol_name: Some("omnigate_auth".to_string()),
                    part_index: None,
                },
            ])
            .unwrap();

        let fused = vec![
            SearchResult {
                file_path: "backend/crates/omnigate-auth/src/lib.rs".to_string(),
                line_start: 10,
                line_end: 40,
                content: "pub use crate::kimi::persist_kimi_auth_record;".to_string(),
                language: Language::Rust,
                score: 0.0,
                symbol_name: Some("omnigate_auth".to_string()),
                symbol_type: Some(SymbolType::Module),
                part_index: None,
            },
            SearchResult {
                file_path: "backend/crates/omnigate-auth/src/factory.rs".to_string(),
                line_start: 286,
                line_end: 296,
                content: "pub fn persist_factory_auth_record() {}".to_string(),
                language: Language::Rust,
                score: 0.0,
                symbol_name: Some("persist_factory_auth_record".to_string()),
                symbol_type: Some(SymbolType::Function),
                part_index: None,
            },
            SearchResult {
                file_path: "backend/crates/omnigate-auth/src/kimi.rs".to_string(),
                line_start: 265,
                line_end: 275,
                content: "pub fn persist_kimi_auth_record() {}".to_string(),
                language: Language::Rust,
                score: 0.0,
                symbol_name: Some("persist_kimi_auth_record".to_string()),
                symbol_type: Some(SymbolType::Function),
                part_index: None,
            },
        ];

        let queries = vec![
            "persist_kimi_auth_record".to_string(),
            "persist_factory_auth_record".to_string(),
        ];
        let augmented = augment_multi_query_exact_matches(
            dir.path(),
            &queries,
            fused,
            &SearchFilters::default(),
            5,
        )
        .unwrap();

        assert_eq!(
            augmented[0].symbol_name.as_deref(),
            Some("persist_kimi_auth_record")
        );
        assert_eq!(
            augmented[1].symbol_name.as_deref(),
            Some("persist_factory_auth_record")
        );
    }

    #[test]
    fn multi_query_exact_matches_interleave_across_queries() {
        let dir = tempdir().unwrap();
        let metadata_path = dir.path().join("metadata.db");
        let store = MetadataStore::open(&metadata_path).unwrap();

        let mut chunks: Vec<Chunk> = (0..5)
            .map(|i| Chunk {
                id: format!("common:{i}"),
                file_path: format!("src/common_{i}.rs"),
                line_start: 1,
                line_end: 10,
                content: "pub fn common_fn() {}".to_string(),
                language: Language::Rust,
                symbol_type: Some(SymbolType::Function),
                symbol_name: Some("common_fn".to_string()),
                part_index: None,
            })
            .collect();
        chunks.push(Chunk {
            id: "rare:0".to_string(),
            file_path: "src/rare.rs".to_string(),
            line_start: 1,
            line_end: 10,
            content: "pub fn rare_fn() {}".to_string(),
            language: Language::Rust,
            symbol_type: Some(SymbolType::Function),
            symbol_name: Some("rare_fn".to_string()),
            part_index: None,
        });
        store.insert_chunks(&chunks).unwrap();

        let augmented = augment_multi_query_exact_matches(
            dir.path(),
            &["common_fn".to_string(), "rare_fn".to_string()],
            Vec::new(),
            &SearchFilters::default(),
            3,
        )
        .unwrap();

        // The first query keeps the top slot, but the second query must
        // contribute instead of being crowded out by the first query's rows.
        assert_eq!(augmented.len(), 3);
        assert_eq!(augmented[0].symbol_name.as_deref(), Some("common_fn"));
        assert_eq!(augmented[1].symbol_name.as_deref(), Some("rare_fn"));
    }

    #[test]
    fn bare_filename_query_gets_exact_file_augmentation() {
        let dir = tempdir().unwrap();
        let metadata_path = dir.path().join("metadata.db");
        let store = MetadataStore::open(&metadata_path).unwrap();
        store
            .insert_chunks(&[
                Chunk {
                    id: "deep:0".to_string(),
                    file_path: "deep/nested/handler.py".to_string(),
                    line_start: 1,
                    line_end: 20,
                    content: "def handle(): pass".to_string(),
                    language: Language::Python,
                    symbol_type: Some(SymbolType::Function),
                    symbol_name: Some("handle".to_string()),
                    part_index: None,
                },
                Chunk {
                    id: "shallow:0".to_string(),
                    file_path: "src/handler.py".to_string(),
                    line_start: 1,
                    line_end: 20,
                    content: "def handle(): pass".to_string(),
                    language: Language::Python,
                    symbol_type: Some(SymbolType::Function),
                    symbol_name: Some("handle".to_string()),
                    part_index: None,
                },
            ])
            .unwrap();

        let augmented = augment_multi_query_exact_matches(
            dir.path(),
            &["handler.py".to_string()],
            Vec::new(),
            &SearchFilters::default(),
            5,
        )
        .unwrap();

        assert!(
            !augmented.is_empty(),
            "a bare filename query must inject exact file chunks"
        );
        assert_eq!(augmented[0].file_path, "src/handler.py");
    }

    // --- Issue #197 latency work: staleness + memory bounds ---

    #[tokio::test]
    async fn cached_index_meta_is_stamp_guarded_and_not_stale() {
        use crate::retrieval::hybrid::SearchStores;
        let dir = tempdir().unwrap();
        let repo = dir.path().join("repo");
        std::fs::create_dir_all(&repo).unwrap();
        std::fs::write(repo.join("a.rs"), "pub fn old_func() {}\n").unwrap();
        let provider = crate::embedding::test_helpers::MockProvider::new(8);
        let config = crate::config::VeraConfig::default();
        crate::indexing::index_repository(&repo, &provider, &config, "mock-model")
            .await
            .unwrap();
        let index_dir = crate::indexing::index_dir(&repo);
        let stores = SearchStores::open(&index_dir).unwrap();
        let (m1, _d1, _p1) = stores.cached_index_meta().unwrap();
        assert_eq!(m1.as_deref(), Some("mock-model"));
        // Record stamp before mutation.
        let stamp_before = std::fs::metadata(index_dir.join("metadata.db"))
            .and_then(|m| m.modified())
            .ok();
        // Simulate external indexer changing model_name (writes WAL, bumps mtime/len).
        {
            let store =
                crate::storage::metadata::MetadataStore::open(&index_dir.join("metadata.db"))
                    .unwrap();
            store.set_index_meta("model_name", "new-model").unwrap();
        }
        // Wait for filesystem mtime granularity: poll until stamp visibly changes or 1.2s elapsed.
        let start = std::time::Instant::now();
        while start.elapsed() < std::time::Duration::from_millis(1200) {
            let current = std::fs::metadata(index_dir.join("metadata.db"))
                .and_then(|m| m.modified())
                .ok();
            if current != stamp_before {
                break;
            }
            std::thread::sleep(std::time::Duration::from_millis(50));
        }
        let (m2, _d2, _p2) = stores.cached_index_meta().unwrap();
        // After stamp invalidation, the new value must be observed; stale cached value is impossible.
        assert_eq!(
            m2.as_deref(),
            Some("new-model"),
            "stale index meta must not be served after stamp change"
        );
        assert_ne!(m1, m2);
    }

    #[tokio::test]
    async fn staleness_proof_modify_file_requery_never_returns_stale_chunk() {
        // Profiling: docs/adr/009-filter-scan-profiling.md — cached state must never serve stale chunks.
        // This test proves cycle-state keying: modify a file, re-index, re-query without
        // restarting SearchContext; the pre-modification chunk is impossible to return.
        use crate::indexing::{index_dir, index_repository};
        let tmp = tempdir().unwrap();
        let repo = tmp.path().join("repo");
        std::fs::create_dir_all(&repo).unwrap();
        let file_path = repo.join("src").join("lib.rs");
        std::fs::create_dir_all(file_path.parent().unwrap()).unwrap();
        std::fs::write(&file_path, "pub fn stale_func() { let x = 1; }\n").unwrap();

        let provider = crate::embedding::test_helpers::MockProvider::new(8);
        let config = crate::config::VeraConfig::default();
        index_repository(&repo, &provider, &config, "mock-model")
            .await
            .unwrap();
        let index_dir = index_dir(&repo);
        // Reuse a single SearchContext across mutation — the bug would be stale Serve.
        let ctx = SearchContext::bm25_only();
        let filters = crate::types::SearchFilters::default();
        let (before, _) = ctx
            .search(&index_dir, "stale_func", None, &config, &filters, 10)
            .await
            .unwrap();
        assert!(
            before.iter().any(|r| r.content.contains("stale_func")),
            "initial index must contain stale_func"
        );
        let stale_chunk_content = before
            .iter()
            .find(|r| r.content.contains("stale_func"))
            .unwrap()
            .content
            .clone();

        // Modify file: replace stale_func with fresh_func
        std::fs::write(&file_path, "pub fn fresh_func() { let y = 2; }\n").unwrap();
        // Re-index (incremental: same index dir)
        index_repository(&repo, &provider, &config, "mock-model")
            .await
            .unwrap();

        // Re-query without restarting context
        let (after_stale, _) = ctx
            .search(&index_dir, "stale_func", None, &config, &filters, 10)
            .await
            .unwrap();
        let (after_fresh, _) = ctx
            .search(&index_dir, "fresh_func", None, &config, &filters, 10)
            .await
            .unwrap();

        // Stale chunk must be impossible to return: no result may contain the old content
        // verbatim. Even if BM25 returns a hit for the query term, its hydrated content must
        // not equal the pre-modification chunk.
        for r in &after_stale {
            assert_ne!(
                r.content, stale_chunk_content,
                "cached state served stale chunk after file modification"
            );
        }
        // Fresh content must be discoverable after re-index.
        assert!(
            after_fresh.iter().any(|r| r.content.contains("fresh_func")),
            "fresh_func must be found after re-index"
        );
        // If stale query happens to still return something (e.g., no filter), ensure it is not
        // the stale chunk; ideally it is empty. Either is acceptable as long as stale is not served.
        // The strongest assertion is that a search for the old symbol returns empty or non-stale.
        assert!(
            after_stale
                .iter()
                .all(|r| !r.content.contains("stale_func")),
            "post-modification query must not return pre-modification chunk content"
        );
    }

    #[test]
    fn memory_bounded_across_multiple_indexed_repos_with_recorded_envelope() {
        // Profiling: docs/adr/009-filter-scan-profiling.md — cross-repo resident store can grow
        // unbounded with single-slot toggle behavior; LRU of 4 caps memory.
        use crate::indexing::{index_dir, index_repository};
        let rt = tokio::runtime::Runtime::new().unwrap();
        let config = crate::config::VeraConfig::default();
        let provider = crate::embedding::test_helpers::MockProvider::new(8);

        // Build 5 distinct indexed repos (capacity is 4)
        let tmps: Vec<tempfile::TempDir> = (0..5).map(|_| tempdir().unwrap()).collect();
        let repos: Vec<std::path::PathBuf> = tmps
            .iter()
            .enumerate()
            .map(|(i, tmp)| {
                let repo = tmp.path().join(format!("repo{i}"));
                std::fs::create_dir_all(&repo).unwrap();
                std::fs::write(
                    repo.join(format!("lib{i}.rs")),
                    format!("pub fn func_{i}() {{}}\n"),
                )
                .unwrap();
                repo
            })
            .collect();
        for repo in &repos {
            rt.block_on(index_repository(repo, &provider, &config, "mock-model"))
                .unwrap();
        }
        let index_dirs: Vec<std::path::PathBuf> = repos.iter().map(|r| index_dir(r)).collect();

        let ctx = SearchContext::bm25_only();
        // Warm each repo once
        for dir in &index_dirs {
            let _ = rt
                .block_on(ctx.search(
                    dir,
                    "func",
                    None,
                    &config,
                    &crate::types::SearchFilters::default(),
                    5,
                ))
                .unwrap();
        }

        // Envelope: cache length and LRU ordering
        let envelope_len = ctx.search_stores_cache_len();
        let envelope_contains = |idx: usize| ctx.search_stores_cache_contains(&index_dirs[idx]);

        // Recorded envelope: must be bounded at capacity 4
        assert_eq!(
            envelope_len,
            4,
            "cache must be bounded at {} (recorded envelope len={})",
            super::SEARCH_STORES_LRU_CAPACITY,
            envelope_len
        );
        // LRU: first repo should have been evicted (oldest), last 4 retained
        assert!(
            !envelope_contains(0),
            "LRU must have evicted oldest repo (0); envelope: len={} contains0={}",
            envelope_len,
            envelope_contains(0)
        );
        for i in 1..5 {
            assert!(
                envelope_contains(i),
                "LRU must retain recent repo {i}; envelope len={envelope_len}"
            );
        }

        // Re-query an evicted repo: must re-open and re-enter cache, still bounded
        let _ = rt
            .block_on(ctx.search(
                &index_dirs[0],
                "func_0",
                None,
                &config,
                &crate::types::SearchFilters::default(),
                5,
            ))
            .unwrap();
        assert_eq!(
            ctx.search_stores_cache_len(),
            4,
            "after re-query evicted repo, cache must remain bounded"
        );
        assert!(
            ctx.search_stores_cache_contains(&index_dirs[0]),
            "evicted repo must be re-cached after re-query"
        );
        // Envelope logging for PR notes (not a file, but printed in test output with --nocapture)
        println!(
            "memory envelope: capacity={}, len={}, retained=[1..4 initially, then 0 after requery], eviction=LRU",
            super::SEARCH_STORES_LRU_CAPACITY,
            ctx.search_stores_cache_len()
        );
    }
}
