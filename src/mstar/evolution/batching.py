"""Co-selected evaluation batching — split (train, val) into semantically aligned batches."""

from __future__ import annotations

import concurrent.futures
import time

import litellm
import numpy as np

from mstar.evolution.azure_config import apply_azure_kwargs
from mstar.evolution.types import DataItem
from mstar.logging.logger import get_logger

_EMBED_BATCH_SIZE = 64
_EMBED_MAX_RETRIES = 3


_LOCAL_EMBED_MODEL = None


def _fastembed_embed(texts: list[str]) -> np.ndarray:
    """Local embedding via FastEmbed (ONNX Runtime, CPU, no API calls)."""
    global _LOCAL_EMBED_MODEL
    if _LOCAL_EMBED_MODEL is None:
        from fastembed import TextEmbedding

        _LOCAL_EMBED_MODEL = TextEmbedding(model_name="BAAI/bge-small-en-v1.5")
    vectors = np.array(list(_LOCAL_EMBED_MODEL.embed(texts)), dtype=np.float64)
    norms = np.linalg.norm(vectors, axis=1, keepdims=True)
    return vectors / np.maximum(norms, 1e-10)


def _embed_texts(texts: list[str], model: str) -> np.ndarray:
    """Encode texts via litellm embedding API, with local FastEmbed fallback.

    Returns L2-normalized vectors.

    - If ``model`` is ``"local"``, uses FastEmbed directly (no API calls).
    - Otherwise, tries the litellm embedding API up to 3 times, then falls back
      to FastEmbed if all attempts fail.
    """
    logger = get_logger()
    if not texts:
        return np.empty((0, 0), dtype=np.float64)
    if model == "local":
        return _fastembed_embed(texts)
    chunks = [texts[start : start + _EMBED_BATCH_SIZE] for start in range(0, len(texts), _EMBED_BATCH_SIZE)]

    def _embed_chunk(chunk: list[str]) -> list[list[float]]:
        for attempt in range(_EMBED_MAX_RETRIES):
            try:
                embed_kwargs: dict = {"model": model, "input": chunk, "caching": True}
                apply_azure_kwargs(model, embed_kwargs)
                response = litellm.embedding(**embed_kwargs)
                return [d["embedding"] for d in response.data]
            except Exception:
                if attempt == _EMBED_MAX_RETRIES - 1:
                    raise
                time.sleep(2**attempt)
        return []  # unreachable

    if len(chunks) == 1:
        try:
            all_embeddings = _embed_chunk(chunks[0])
        except Exception:
            logger.log(
                f"Embedding API failed after {_EMBED_MAX_RETRIES} attempts, falling back to local FastEmbed",
                header="EMBED",
            )
            return _fastembed_embed(texts)
    else:
        with concurrent.futures.ThreadPoolExecutor(max_workers=min(len(chunks), 8)) as pool:
            futures = {pool.submit(_embed_chunk, c): i for i, c in enumerate(chunks)}
            chunk_results: list[list[list[float]] | None] = [None] * len(chunks)
            try:
                for fut in concurrent.futures.as_completed(futures):
                    idx = futures[fut]
                    chunk_results[idx] = fut.result()
            except Exception:
                logger.log(
                    f"Embedding API failed after {_EMBED_MAX_RETRIES} attempts, falling back to local FastEmbed",
                    header="EMBED",
                )
                return _fastembed_embed(texts)
        all_embeddings = [emb for cr in chunk_results for emb in cr]  # type: ignore[union-attr]
    vectors = np.array(all_embeddings, dtype=np.float64)
    norms = np.linalg.norm(vectors, axis=1, keepdims=True)
    return vectors / np.maximum(norms, 1e-10)


def _kmeans(vectors: np.ndarray, k: int, max_iter: int = 50, seed: int = 42) -> np.ndarray:
    """Lloyd's algorithm with cosine distance on L2-normalized vectors.

    Args:
        vectors: (n, d) L2-normalized array.
        k: Number of clusters.

    Returns:
        labels: (n,) integer cluster assignments.
    """
    n = len(vectors)
    rng = np.random.RandomState(seed)
    indices = rng.choice(n, k, replace=n < k)
    centers = vectors[indices].copy()

    for _ in range(max_iter):
        sim = vectors @ centers.T  # (n, k)
        labels = sim.argmax(axis=1)

        new_centers = np.zeros_like(centers)
        for i in range(k):
            mask = labels == i
            if mask.any():
                new_centers[i] = vectors[mask].mean(axis=0)
            else:
                new_centers[i] = vectors[rng.randint(n)]

        norms = np.linalg.norm(new_centers, axis=1, keepdims=True)
        new_centers = new_centers / np.maximum(norms, 1e-10)

        if np.allclose(centers, new_centers, atol=1e-8):
            break
        centers = new_centers

    return labels


def _select_train_subset(
    val_embs: np.ndarray,
    train_embs: np.ndarray,
    budget: int,
    threshold: float | None = None,
) -> tuple[list[int], float]:
    """Greedy facility location: select train items maximizing coverage of val items.

    Args:
        val_embs: (m, d) L2-normalized val embeddings.
        train_embs: (N, d) L2-normalized train embeddings.
        budget: Max number of train items to select.
        threshold: Stop when marginal gain falls below this.

    Returns:
        (selected_indices, coverage) where coverage = mean max similarity.
    """
    if len(val_embs) == 0:
        return [], 0.0

    sim = val_embs @ train_embs.T  # (m, N)
    current_max = np.full(len(val_embs), -np.inf)
    selected: list[int] = []
    mask = np.ones(sim.shape[1], dtype=bool)

    for _ in range(min(budget, len(train_embs))):
        gains = np.maximum(sim[:, mask] - current_max[:, None], 0).sum(axis=0)
        if threshold is not None and gains.max() < threshold:
            break
        available_indices = np.where(mask)[0]
        best_local = int(gains.argmax())
        best = int(available_indices[best_local])
        selected.append(best)
        current_max = np.maximum(current_max, sim[:, best])
        mask[best] = False

    coverage = float(current_max.mean()) if selected else 0.0
    return selected, coverage


def _balance_clusters(
    labels: np.ndarray,
    vectors: np.ndarray,
    centers: np.ndarray,
    target_size: int,
) -> list[list[int]]:
    """Balance K-means clusters to target_size items each.

    Oversized clusters keep items closest to centroid.
    Undersized clusters fill from unassigned pool (nearest to centroid).
    Last cluster absorbs remainder when n % k != 0.

    Returns:
        List of K lists of original indices.
    """
    k = len(centers)

    # Sort each cluster by similarity to centroid (highest first)
    raw_clusters: list[list[int]] = [[] for _ in range(k)]
    for idx, label in enumerate(labels):
        raw_clusters[label].append(idx)

    for i in range(k):
        members = raw_clusters[i]
        if len(members) > 1:
            sims = vectors[members] @ centers[i]
            order = np.argsort(-sims)
            raw_clusters[i] = [members[j] for j in order]

    # Phase 1: trim oversized, collect surplus
    balanced: list[list[int]] = [[] for _ in range(k)]
    pool: list[int] = []
    for i in range(k):
        if i == k - 1:
            balanced[i] = raw_clusters[i]
        elif len(raw_clusters[i]) > target_size:
            balanced[i] = raw_clusters[i][:target_size]
            pool.extend(raw_clusters[i][target_size:])
        else:
            balanced[i] = raw_clusters[i]

    # Phase 2: fill undersized from pool
    for i in range(k - 1):
        deficit = target_size - len(balanced[i])
        if deficit > 0 and pool:
            pool_sims = vectors[pool] @ centers[i]
            order = np.argsort(-pool_sims)
            fill_count = min(deficit, len(pool))
            fill_indices = [pool[order[j]] for j in range(fill_count)]
            balanced[i].extend(fill_indices)
            fill_set = set(fill_indices)
            pool = [p for p in pool if p not in fill_set]

    # Remaining pool to last cluster
    balanced[k - 1] = balanced[k - 1] + pool

    return balanced


def select_representative_subset(
    train_data: list[DataItem],
    val_data: list[DataItem],
    val_size: int,
    train_val_ratio: int = 5,
    embedding_model: str = "openrouter/baai/bge-m3",
) -> tuple[list[int], list[int]]:
    """Select a representative (train, val) subset covering all val clusters.

    Uses k-means to cluster val items, picks the closest item to each centroid,
    then uses facility location to select train items that cover the selected val items.

    If val_size >= len(val_data), returns all indices (degrades to FullDataset).

    Returns:
        (train_indices, val_indices)
    """
    logger = get_logger()

    if val_size >= len(val_data):
        logger.log(
            f"val_size ({val_size}) >= val data ({len(val_data)}), using all items",
            header="SUBSET",
        )
        val_indices = list(range(len(val_data)))
    else:
        val_texts = [item.question for item in val_data]
        logger.log(f"Embedding {len(val_texts)} val texts for representative selection...", header="SUBSET")
        val_embs = _embed_texts(val_texts, model=embedding_model)
        labels = _kmeans(val_embs, k=val_size)
        rng = np.random.RandomState(42)
        val_indices = []
        for c in range(val_size):
            members = [i for i, label in enumerate(labels) if label == c]
            if not members:
                continue
            val_indices.append(members[rng.randint(len(members))])

        logger.log(f"Selected {len(val_indices)} representative val items from {val_size} clusters", header="SUBSET")

    train_texts = [item.raw_text if item.raw_text else item.question for item in train_data]
    if train_texts:
        budget = len(train_data) if train_val_ratio < 0 else train_val_ratio * len(val_indices)
        logger.log(f"Embedding {len(train_texts)} train texts...", header="SUBSET")
        try:
            train_embs = _embed_texts(train_texts, model=embedding_model)

            val_texts_for_embed = [item.question for item in val_data]
            if val_size < len(val_data):
                subset_val_embs = val_embs[val_indices]
            else:
                val_embs_full = _embed_texts(val_texts_for_embed, model=embedding_model)
                subset_val_embs = val_embs_full[val_indices]

            train_indices, coverage = _select_train_subset(subset_val_embs, train_embs, budget=budget)
        except Exception:
            logger.log("Train embedding failed, falling back to random train selection", header="SUBSET")
            import random as _rand

            rng = _rand.Random(42)
            train_indices = rng.sample(range(len(train_data)), min(budget, len(train_data)))
            coverage = 0.0
    else:
        train_indices: list[int] = []
        coverage = 0.0
        budget = 0
    logger.log(
        f"Selected {len(train_indices)} train items (budget={budget}, coverage={coverage:.4f})",
        header="SUBSET",
    )

    return train_indices, val_indices
