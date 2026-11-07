# Downstream task and generation

This directory contains the downstream modules that consume the ranked Steam review passages returned by the retriever.

| Component | Location | Purpose |
|---|---|---|
| Aspect-based Sentiment Analysis | Provided by the classification contributor | Predict aspect-level sentiment from the review evidence |
| Evidence-grounded RAG summarization | `generation/rag_summary/` | Answer the user question with review citations |

The two components can use the same retrieved passages. The summarizer reads the review text directly and does not require predicted sentiment labels from the classification component. Its implementation and experiment instructions are documented in `rag_summary/README.md`.

## Connecting to the UI

`code/app.py` already computes `query` and a final ranked `hits` list. Its placeholder titled **"Sentiment analysis / generated answer"** is the integration point. The summarization function is:

```python
from generation.rag_summary.rag_generator import generate_summary

result = generate_summary(query, hits, max_claims=4)
```

Configure the API environment variables below before making this call. Run integration commands from **`code/`**, so imports from `generation`, `retrieval`, and `paths` resolve.

### Retrieval input

Pass the original question and the same final `hits` list displayed by the app. Each hit is a dictionary with:

The updated app requires at least one explicitly selected game before retrieval or generation. It passes the selected games as a `game_name` filter to both sparse and dense search, restricts candidates before fusion/reranking, and checks final evidence again before generation. Multiple selected games support comparisons. `metadata.game_name` is required at this app boundary; missing or out-of-scope game identities are excluded. Saved answers record `retrieval_filters`.

| Key | Content and use |
|---|---|
| `chunk_id` | Required. Original passage ID, retained in citations |
| `text` | Required. Review evidence used to generate the answer |
| `metadata` | Optional dictionary containing source information |
| `metadata.game_name` | Game identity used when interpreting the passage |
| `metadata.source_url` | Original review URL retained in the output citations |
| `metadata.created_at_utc`, `metadata.updated_at_utc` | Review timestamps; Unix `timestamp_created`/`timestamp_updated` are also accepted |
| `metadata.helpful_votes` or `metadata.votes_up` | Helpful vote count used for vote-aware attribution and the publication-age weight |
| `metadata.review_id`, `appid`, `document_id`, `chunk_index`, `char_start` | Optional identity and chunk-position information for temporal selection |

Additional metadata such as `source` and `title` can remain in the hit. Rank and score fields such as `retrieved_by`, `sparse_rank`, `dense_rank`, `rrf_rank`, `rrf_score`, and `score` are not added to the model context. The ranked list order is preserved, duplicate passage IDs are removed, and the original user question is used rather than the expanded retrieval query.

Live generation defaults to `context_policy="latest_update"`: among multiple snapshots of one review, only the newest available snapshot is retained. Explicit substantive `Edit:`/`Update:` sections are reduced to the latest visible update and continuation, including updates spanning multiple supplied chunks. Earlier opinions are excluded from the model context. Wording-only edit notes do not replace the review. If update boundaries are absent, the latest full snapshot is used. Available review timestamps and an `evidence_scope` field accompany the text. Original stored reviews and citation IDs are preserved. Update the complete `rag_summary/` module, including `review_context.py`, when installing this behavior.

The same live context includes recorded `helpful_votes`, `review_age_days`, and `helpful_votes_per_day` when available. The weight is `helpful_votes / max(days_since_first_publication, 1)`. Last-edit timestamps do not reset review age. Missing or invalid inputs leave the weight unavailable. One shared `as_of_utc` is used across generation and self-check stages. `is_high_helpfulness` marks reviews meeting both a ten-vote minimum and the nearest-rank upper quartile of distinct visible reviews. Answer prose may call these reviews “highly upvoted” but omits raw counts and rates; lower-vote sources are blended into the answer without vote attribution. Votes do not establish consensus. Retrieval order is unchanged.

The prompt asks for a coherent answer organized around the question. Overlapping information is merged and the `claims` array follows paragraph order, rather than allocating one mini-summary to each review. Source citations, important conditions and disagreements remain required. No background, popularity, recency or mod-development facts are added just to improve the prose.

No conversion is required between the app's final `hits` list and the summarizer. BM25-only, dense-only, fused, and reranked results use the same input contract.

### API configuration

Set the following environment variables in the shell or hosting environment before starting the app:

| Variable | Example or purpose |
|---|---|
| `GENERATION_API_KEY` | Your generation provider's API key |
| `GENERATION_BASE_URL` | `https://api.deepseek.com` |
| `GENERATION_MODEL` | `deepseek-v4-pro` |

The API must support OpenAI-compatible Chat Completions and JSON object output. The summarizer reads credentials from the environment. Keys are not included in generated result files. Official DeepSeek V4 thinking is disabled automatically by the default client configuration.

### Streamlit integration

Use the tested replacement `app.py` and patch supplied in `rag_summary/integration/`, based on group `main` commit `ab5844e`. For a manual integration, require a game selection before search and pass the `game_name` filter to both retrievers. The block below handles generation in the existing container. Keep the classification component's UI alongside the summary. The app already imports `json` and `streamlit as st`, and defines `query`, `hits`, and the selected `games`.

```python
import os

from paths import GENERATION_RESULTS_DIR
from generation.rag_summary.rag_generator import (
    GenerationError,
    OpenAICompatibleClient,
    generate_summary,
    safe_error,
)

st.markdown("**Evidence-grounded review summary**")
if not games:
    st.info("Select at least one target game before generating a summary.")
    st.stop()
hits = [h for h in hits if (h.get("metadata") or {}).get("game_name") in games]
if not hits:
    st.warning("No reviews match the selected games.")
    st.stop()
evidence_key = (query, tuple(sorted(games)), tuple(
    (h["chunk_id"], h["text"], json.dumps(h.get("metadata") or {}, sort_keys=True))
    for h in hits
))

if st.button("Generate summary", key="rag_summary_generate"):
    try:
        with st.spinner("Generating an answer from the retrieved reviews..."):
            result = generate_summary(
                query,
                hits,
                model=os.getenv("GENERATION_MODEL", "deepseek-v4-pro"),
                client=OpenAICompatibleClient(
                    base_url=os.getenv("GENERATION_BASE_URL", "https://api.deepseek.com")
                ),
                max_claims=4,
            )
        result["retrieval_filters"] = {"game_name": list(games)}
        st.session_state["rag_summary_answer"] = (evidence_key, result)
        output_dir = GENERATION_RESULTS_DIR / "rag_summary"
        output_dir.mkdir(parents=True, exist_ok=True)
        (output_dir / "latest_answer.json").write_text(
            json.dumps(result, ensure_ascii=False, indent=2), encoding="utf-8"
        )
    except GenerationError as error:
        st.error(safe_error(error)["error_message"])

saved = st.session_state.get("rag_summary_answer")
if saved is not None and saved[0] == evidence_key:
    result = saved[1]
    st.markdown(result["summary"])
    for citation in result["citations"]:
        if citation["source_url"]:
            st.link_button(citation["chunk_id"], citation["source_url"])
    st.download_button(
        "Download generated answer",
        json.dumps(result, ensure_ascii=False, indent=2),
        file_name="rag_summary.json",
        mime="application/json",
        key="rag_summary_download",
    )
```

Run the existing search interface from `code/`:

```bash
streamlit run app.py
```

Select the target game or games, search for reviews, then click **Generate summary**. Only this button initiates generation. Streamlit reruns reuse the saved answer when the question, game scope and evidence are unchanged. The example saves the latest answer to `data/generation_results/rag_summary/latest_answer.json` through the shared `paths.py` configuration.

### Generation output

The returned dictionary contains:

| Field | Content |
|---|---|
| `summary` | Answer text with inline `[chunk_id]` citations |
| `claims` | Answer sentences and supporting `chunk_ids` |
| `citations` | Unique cited passage IDs and available source URLs |
| `status` | `ok`, `abstained`, or `no_evidence` |
| `usage` | Available input/output token counts |
| `latency_seconds` | Generation workflow time |
| `stage_calls`, `claim_audit` | Generation and citation-validation records |
| `context_policy`, `context_evidence` | The selected policy and actual latest-update context used by the model |
| `context_as_of_utc`, `review_weight_formula` | Reference time and formula used to calculate live review weights |
| `retrieval_filters` | Selected game scope recorded by the integrated app |

Generation uses one model call. Optional `few_shot_examples` and `compression_ratio` arguments enable demonstrations and local sentence extraction; `approach` in the returned result records the inferred configuration. Source IDs are checked against the actual model context.

## Using retrieval directly

Run from `code/`. The following example follows the group's query expansion, fusion, and reranking pipeline, then generates an answer from the final results:

```python
from generation.rag_summary.rag_generator import generate_summary
from retrieval.hybrid_retriever import HybridRetriever
from retrieval.query_expansion import expand_query
from retrieval.reranker import Reranker

query = "How is the soundtrack in Hollow Knight?"
expansion = expand_query(query, mode="hierarchical")
fused = HybridRetriever().retrieve_fused(
    query,
    top_k=30,
    candidates=20,
    filters={"game_name": ["Hollow Knight"]},
    sparse_query=expansion.sparse,
    dense_query=expansion.dense,
)
hits = Reranker().rerank(query, fused, top_k=5)
result = generate_summary(query, hits, max_claims=4)
```

`HybridRetriever.retrieve()` returns separate sparse and dense lists. Use the final list from fusion or reranking as the generation input.

### Using the UI's JSON export

The search interface's **Download results (JSON)** button produces `search_results.json` containing `query` and `results`. The generator accepts this structure directly. Save the export to `data/retrieval_results/search_results.json`, set the API environment variables, and run from `code/`:

```bash
python -c "from paths import GENERATION_RESULTS_DIR; (GENERATION_RESULTS_DIR / 'rag_summary').mkdir(parents=True, exist_ok=True)"
python generation/rag_summary/rag_generator.py ../data/retrieval_results/search_results.json --max-claims 4 --output ../data/generation_results/rag_summary/answer.json
```

Fields such as `mode`, `filters`, `params`, `expansion`, and `timings_ms` remain in the retrieval export and are not passed to the model as review evidence.

## Evaluation

The summarization experiment compares four independent generation methods: `baseline`, `few_shot`, `compressed`, and `combined`. They share the baseline prompt and citation schema. The web experiment does not run the historical self-check methods.

The fixed 100-question benchmark has a frozen stratified split: 20 development questions (q06 and q24 are demonstrations; 18 questions remain for tuning) and 80 test questions. Few-shot methods receive only the two development demonstrations. The current question's reference answer is used solely for local ROUGE-1/2/L scoring. All nine precision/recall/F1 scores, actual API tokens, latency, text retention and optional cost are exported.

The original evidence uses `context_policy="full_review"` and `include_review_metadata=True`. Compression methods locally select related sentences with TF-IDF and redundancy reduction, preferring adjacent sentences within a configurable text budget (default 0.6). Original IDs, metadata and exact selected text remain traceable through character spans. The live app's selected-game and latest-update policies operate separately.

From `code/`, after configuring the generation API:

```bash
python generation/rag_summary/run_generation_experiments.py --output ../data/generation_results/rag_summary/fewshot_compression_test --split test --limit 80 --compression-ratio 0.6 --concurrency 20 --max-retries 2 --repeats 1 --max-claims 4 --base-url https://api.deepseek.com --model deepseek-v4-pro
```

Web and CLI experiments default to 20 concurrent tasks (configurable 1–500) and two retries after the initial request. Retries use the same prompt for transient failures, invalid JSON/claims or invalid source IDs. Valid abstention is not retried. Per-task latency and usage include attempts; attempt histories and run totals are exported. Configuration/account errors stop new requests; other final failures do not stop the run.

Use `--split development --limit 18` to try settings. Run the same workflow with progress and ZIP download through `python generation/rag_summary/launch_web.py`. Restart an older server and refresh after updating.

Rescore a result ZIP without API calls:

```bash
python generation/rag_summary/evaluate_generation.py generation-experiment.zip --output ../data/generation_results/rag_summary/rouge_rescored
```

Outputs include the exact data split, demonstrations, original and actual evidence, all ROUGE scores, execution metrics, five paired comparisons and the two-factor interaction. Archived fact-ID result files remain available in `experiments/final/`; the old evaluation code and compatibility entry points have been removed.

Use new output directories. Upload the updated complete `rag_summary/` module, including `experiment_execution.py`, `context_compression.py`, `generation_experiment_design.py`, `prompts/few_shot.txt`, `data/generation_experiment/` and the reviewed references. Full settings are in `rag_summary/README.md`.

The classification contributor should document the classification interface, execution commands, and evaluation alongside this summarization interface.

## Conventions

- Run group integration commands from `code/` and take shared data locations from `paths.py`.
- Write integrated generation outputs and task-specific evaluation results under `GENERATION_RESULTS_DIR`, using separate subdirectories for each component. The summarizer uses `data/generation_results/rag_summary/`.
- The summarizer's bundled benchmark data and archived results remain inside `rag_summary/` for reproduction; the integration examples write new outputs to the shared data directory.
- Add any new dependencies to `code/requirements.txt` with pinned versions. The summarization module itself uses only the Python standard library.
- Read API keys from environment variables. `.env` is ignored by git and excluded from submission packages; this summarizer does not load `.env` files automatically.
- Keep the internal implementation instructions in each component's own README. This README describes the handoff between retrieval, the shared app, and the downstream modules.
- Update the downstream-task entry in the root `README.md` when the modules are integrated.
