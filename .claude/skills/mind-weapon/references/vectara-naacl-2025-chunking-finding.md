# Vectara NAACL 2025: Is Semantic Chunking Worth the Computational Cost?

> **Status:** **LOAD-BEARING REFERENCE.** Carried over verbatim from the retired `ai-platform-weapon`. This is the canonical defense against vendor "semantic chunking" claims.
>
> **Source:** https://arxiv.org/abs/2410.13070 (Vectara, accepted at NAACL 2025).
> **Original retrieval date:** 2026-04-25.

---

## TL;DR

> "Fixed-size chunking consistently performs as well or better than the more computationally expensive semantic chunking methods on realistic document sets."

This contradicts a swath of vendor blog posts (Weaviate, Pinecone, LangChain, others) claiming 15–40% retrieval lifts from semantic chunking. The Vectara paper benchmarks on realistic corpora and finds the lift is at best small and inconsistent, often negative once compute cost is accounted for.

---

## Methods compared

1. **Fixed-size chunking** — recursive character splitting at a target chunk length.
2. **Semantic chunking (Kamradt 2024)** — split between sentences when embedding similarity drops below a threshold.
3. **Proposed semantic-cluster method** — a Vectara-proposed method.

---

## Datasets

Three realistic retrieval tasks, multiple embedding models. The realistic-corpora detail matters — many vendor benchmarks use synthetic or hand-picked content where semantic boundaries align cleanly. Real enterprise corpora rarely have that property.

---

## Headline result

Across the three tasks and the multiple embedders tested, fixed-size chunking via recursive character splitting matched or beat semantic chunking. The proposed semantic-cluster method did not produce a consistent lift either.

---

## Why this matters for the deploying product

the deploying product's `chunkText()` in `knowledge-indexer.ts` produces 500-character chunks with 20% overlap — **fixed-size recursive character splitting**. This is the canonical default per Vectara NAACL 2025.

When a contributor proposes adopting "semantic chunking" because of a vendor blog:

> "Per the Vectara NAACL 2025 paper (arXiv:2410.13070), fixed-size chunking via recursive character splitting consistently performs as well or better than semantic chunking on realistic document sets. We recommend recursive character splitting as the default, with semantic / contextual / late / hierarchical chunking adopted only when (a) there's a clear use-case reason and (b) you can eval the lift on your own corpus."

Severity: usually **should-refactor** ("revert to recursive character unless eval'd"). Becomes **must-fix** when semantic chunking has been adopted in production without an eval suite.

---

## Caveats / what the paper does NOT say

- It does NOT say semantic chunking *never* helps. On specific corpora (long structured documents, certain academic papers), it can.
- It does NOT cover **contextual retrieval** (Anthropic) or **late chunking** (Jina) — these are different optimizations that can pay off independently.
- It does NOT eliminate the need for chunking experimentation on your specific corpus — it shifts the prior.

---

## product-specific note: 500-char chunks below Cohere's optimal window

the deploying product's 500-char (~125-token) chunks are **smaller** than Cohere's optimal ~512-token window. Per `guides/07-knowledge-base.md §5`:

> 500 characters (~125 tokens) is below the optimal Cohere window of ~512 tokens. The current implementation trades retrieval quality for smaller Qdrant point counts. A migration to 512-token chunks with re-indexing would improve precision.

This is a **separate question** from semantic-vs-fixed-size. Even within fixed-size chunking, chunk size matters. The Vectara finding says "use recursive character splitting"; chunk size is then tuned by `scripts/retrieval-precision-snapshot.ts` runs on the corpus.

A migration from 500 chars to ~2000 chars (~512 tokens) would require:

1. Eval baseline at current 500 chars.
2. Re-index a sample of the corpus at ~2000 chars.
3. Eval at new chunk size.
4. Adopt only if lift > 5% on retrieval precision.

---

## Related research notes

- `research/2026-04-25-vectara-naacl-2025-chunking.md` (mind-weapon's research/ folder — same content, different file path)
- `research/2026-04-25-anthropic-contextual-retrieval.md` (different optimization, can stack with fixed-size chunking)

---

## Numbers tag

This finding is **benchmarked** (paper with code, datasets, reproduction). The vendor counterclaims are **vendor-directional**. Always cite the source paper, not the vendor blog.
