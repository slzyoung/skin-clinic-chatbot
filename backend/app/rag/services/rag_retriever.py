import os
import re
import pickle
from datetime import datetime, date, timezone
from typing import List, Dict, Any, Optional
from loguru import logger
# pyrefly: ignore [missing-import]
from rank_bm25 import BM25Okapi

from app.rag.services.interfaces import BaseVectorStoreAdapter
from app.rag.config import settings


# --- Temporal Filtering Helpers ---

def parse_date_safely(date_val: Any) -> Optional[date]:
    """Parses various date string formats safely into a date object."""
    if not date_val:
        return None
    if isinstance(date_val, date) and not isinstance(date_val, datetime):
        return date_val
    if isinstance(date_val, datetime):
        return date_val.date()
    
    date_str = str(date_val).strip()
    if not date_str or date_str.lower() in ("null", "none", "undefined", ""):
        return None

    # Strip time part if present (e.g. 2026-08-31T00:00:00Z)
    if "t" in date_str.lower():
        date_str = date_str.split("T")[0].split("t")[0]
    if " " in date_str:
        date_str = date_str.split(" ")[0]

    date_formats = [
        "%Y-%m-%d",
        "%Y/%m/%d",
        "%d-%m-%Y",
        "%d/%m/%Y",
        "%Y.%m.%d",
        "%d.%m.%Y"
    ]
    for fmt in date_formats:
        try:
            return datetime.strptime(date_str, fmt).date()
        except ValueError:
            continue
    return None


def is_chunk_valid_temporal(
    metadata: Dict[str, Any], 
    current_date: Optional[date] = None, 
    include_expired: bool = False
) -> bool:
    """
    Checks if a chunk is currently active and not expired.
    - If include_expired is True: always returns True.
    - If valid_until is present and valid_until < current_date: returns False (expired).
    - If valid_from is present and current_date < valid_from: returns False (future/not yet active).
    """
    if include_expired:
        return True

    if not metadata:
        return True

    today = current_date or datetime.now(timezone.utc).date()

    valid_until_str = metadata.get("valid_until") or metadata.get("expiry_date") or metadata.get("end_date")
    if valid_until_str:
        until_date = parse_date_safely(valid_until_str)
        if until_date and until_date < today:
            return False

    valid_from_str = metadata.get("valid_from") or metadata.get("start_date")
    if valid_from_str:
        from_date = parse_date_safely(valid_from_str)
        if from_date and today < from_date:
            return False

    return True


# --- Local BM25 Index ---
class BM25Index:
    def __init__(self):
        self.chunks: List[Dict[str, Any]] = []       # Original chunks with text and metadata
        self.corpus: List[List[str]] = []            # Tokenized corpus for BM25
        self.bm25: Optional[BM25Okapi] = None         # rank-bm25 object

    def tokenize(self, text: str) -> List[str]:
        """Simple lowercase alphanumeric word tokenization."""
        if not text:
            return []
        return re.findall(r'\w+', text.lower())

    def add_chunks(self, new_chunks: List[Dict[str, Any]]):
        """Adds new chunks to the BM25 index, removing old chunks of the same source file first."""
        if not new_chunks:
            return

        # Try to extract the source_file name to clear older entries
        source_file = new_chunks[0].get("metadata", {}).get("source_file")
        if source_file:
            logger.debug(f"Clearing old BM25 chunks for source file: {source_file}")
            self.remove_file_chunks(source_file)

        for chunk in new_chunks:
            text = chunk.get("text", "")
            metadata = chunk.get("metadata", {})
            self.chunks.append({
                "text": text,
                "metadata": metadata
            })
            self.corpus.append(self.tokenize(text))

        # Re-initialize the BM25 model with the updated corpus
        if self.corpus:
            self.bm25 = BM25Okapi(self.corpus)
            logger.info(f"Re-initialized BM25 index. Total chunks in index: {len(self.chunks)}")
        else:
            self.bm25 = None

    def remove_file_chunks(self, source_file: str):
        """Removes all chunks associated with a given source file name or knowledge_id."""
        s_clean = str(source_file).strip().lower()
        indices_to_keep = []
        for i, chunk in enumerate(self.chunks):
            meta = chunk.get("metadata", {}) if isinstance(chunk, dict) else {}
            chunk_source = str(meta.get("source_file", "")).strip().lower()
            chunk_kid = str(meta.get("knowledge_id", "")).strip().lower()
            chunk_fname = str(meta.get("file_name", "")).strip().lower()
            if s_clean not in (chunk_source, chunk_kid, chunk_fname):
                indices_to_keep.append(i)
        self.chunks = [self.chunks[i] for i in indices_to_keep]
        self.corpus = [self.corpus[i] for i in indices_to_keep]
        
        if self.corpus:
            self.bm25 = BM25Okapi(self.corpus)
        else:
            self.bm25 = None

    def clear(self):
        """Clears all chunks and corpus, resetting the BM25 index state."""
        self.chunks = []
        self.corpus = []
        self.bm25 = None


    def search(
        self, 
        query: str, 
        top_k: int = 5, 
        filter_metadata: Optional[Dict[str, Any]] = None,
        include_expired: bool = False
    ) -> List[Dict[str, Any]]:
        """
        Searches the corpus using BM25.
        Applies metadata filtering and temporal validity before scoring if filter_metadata is provided.
        """
        if not self.chunks:
            return []

        today = datetime.now(timezone.utc).date()

        # Step 1: Filter chunk candidates by metadata and temporal validity
        filtered_indices = []
        for idx, chunk in enumerate(self.chunks):
            meta = chunk.get("metadata", {})
            
            # Check temporal validity for promo/dated documents
            if not is_chunk_valid_temporal(meta, current_date=today, include_expired=include_expired):
                continue

            match = True
            if filter_metadata:
                for k, v in filter_metadata.items():
                    if k == "excluded_categories" and isinstance(v, list):
                        chunk_cats = meta.get("categories", [])
                        if not isinstance(chunk_cats, list):
                            chunk_cats = [chunk_cats] if chunk_cats else []
                        if any(item in chunk_cats for item in v if item):
                            match = False
                            break
                    elif isinstance(v, list):
                        chunk_val = meta.get(k)
                        # If chunk has no restriction, or has 'all', or query filter allows 'all', it matches
                        if chunk_val is None or chunk_val == [] or "all" in v:
                            continue
                        if not isinstance(chunk_val, list):
                            chunk_val = [chunk_val]
                        if "all" in chunk_val:
                            continue
                        if not any(item in chunk_val for item in v if item):
                            match = False
                            break
                    elif meta.get(k) != v:
                        match = False
                        break
            if match:
                filtered_indices.append(idx)

        if not filtered_indices:
            logger.debug(f"No chunks matched metadata filter {filter_metadata} in BM25 index.")
            return []

        tokenized_query = self.tokenize(query)

        # Step 2: Calculate BM25 scores
        # If we have a filter, build a temporary BM25 okapi index of just the filtered candidates
        if (filter_metadata or not include_expired) and len(filtered_indices) < len(self.chunks):
            filtered_corpus = [self.corpus[i] for i in filtered_indices]
            temp_bm25 = BM25Okapi(filtered_corpus)
            scores = temp_bm25.get_scores(tokenized_query)
            
            top_temp_indices = sorted(range(len(scores)), key=lambda i: scores[i], reverse=True)[:top_k]
            results = []
            for idx in top_temp_indices:
                score = scores[idx]
                if score == 0.0:  # Skip chunks with absolutely zero term matches
                    continue
                orig_idx = filtered_indices[idx]
                results.append({
                    "text": self.chunks[orig_idx]["text"],
                    "score": float(score),
                    "metadata": self.chunks[orig_idx]["metadata"]
                })
            return results
        else:
            # Score against global BM25 model
            if not self.bm25:
                return []
            scores = self.bm25.get_scores(tokenized_query)
            top_indices = sorted(range(len(scores)), key=lambda i: scores[i], reverse=True)[:top_k]
            results = []
            for idx in top_indices:
                score = scores[idx]
                if score == 0.0:  # Skip chunks with absolutely zero term matches
                    continue
                results.append({
                    "text": self.chunks[idx]["text"],
                    "score": float(score),
                    "metadata": self.chunks[idx]["metadata"]
                })
            return results

    def save(self, file_path: str = None):
        """Serializes and saves the index to MinIO (SSOT) and local disk fallback atomically."""
        try:
            payload = {
                "chunks": self.chunks,
                "corpus": self.corpus
            }
            pickle_bytes = pickle.dumps(payload)

            # 1. Save to MinIO Object Storage (SSOT)
            try:
                from app.services.storage import _get_client, _docs_bucket
                client = _get_client()
                if client:
                    client.put_object(
                        Bucket=_docs_bucket(),
                        Key="indexes/bm25_index.pkl",
                        Body=pickle_bytes,
                        ContentType="application/octet-stream"
                    )
                    logger.info(f"✅ Successfully saved BM25 index to MinIO '{_docs_bucket()}/indexes/bm25_index.pkl' ({len(self.chunks)} chunks)")
            except Exception as s3_err:
                logger.debug(f"MinIO BM25 save note: {s3_err}")

            # 2. Local fallback if path provided
            if file_path:
                parent_dir = os.path.dirname(file_path)
                if parent_dir:
                    os.makedirs(parent_dir, exist_ok=True)
                tmp_path = f"{file_path}.tmp"
                with open(tmp_path, "wb") as f:
                    f.write(pickle_bytes)
                os.replace(tmp_path, file_path)
                logger.debug(f"Saved BM25 index locally to {file_path}")
        except Exception as e:
            logger.error(f"Failed to save BM25 index: {e}")

    def load(self, file_path: str = None):
        """Loads and deserializes the index from MinIO (SSOT) with local disk fallback."""
        data = None

        # 1. Fast MinIO fetch (SSOT)
        try:
            from app.services.storage import _get_client, _docs_bucket
            client = _get_client()
            if client:
                resp = client.get_object(Bucket=_docs_bucket(), Key="indexes/bm25_index.pkl")
                data = pickle.loads(resp["Body"].read())
                logger.info(f"⚡ Successfully loaded BM25 index from MinIO '{_docs_bucket()}/indexes/bm25_index.pkl'")
        except Exception as s3_err:
            logger.debug(f"MinIO BM25 load note: {s3_err}")

        # 2. Local fallback if not found in MinIO
        if not data and file_path and os.path.exists(file_path):
            try:
                with open(file_path, "rb") as f:
                    data = pickle.load(f)
                logger.info(f"Loaded BM25 index from local file {file_path}")
            except Exception as e:
                logger.error(f"Failed to load local BM25 index: {e}")

        if data:
            self.chunks = data.get("chunks", [])
            self.corpus = data.get("corpus", [])
            if self.corpus:
                self.bm25 = BM25Okapi(self.corpus)
                logger.info(f"Successfully initialized BM25Okapi with {len(self.chunks)} chunks.")
            else:
                self.bm25 = None
        else:
            logger.info("No existing BM25 index found in MinIO or disk. Starting with clean index.")


# --- Cross-Encoder Reranker ---
class Reranker:
    def __init__(self, model_name: str = "BAAI/bge-reranker-base"):
        self.model_name = model_name
        self.model = None
        self._initialized = False

    def _ensure_loaded(self):
        if not self._initialized:
            self._initialized = True
            logger.info(f"Loading Cross-Encoder Reranker model: {self.model_name}...")
            try:
                from sentence_transformers import CrossEncoder
                self.model = CrossEncoder(self.model_name)
                logger.info("Cross-Encoder Reranker model loaded successfully.")
            except Exception as e:
                logger.error(f"Failed to load CrossEncoder model: {e}")
                self.model = None

    def rerank(self, query: str, hits: List[Dict[str, Any]], top_n: int = 3) -> List[Dict[str, Any]]:
        """
        Reranks retrieve search candidates using the Cross-Encoder.
        Optimized for fast CPU inference (< 200ms) by clipping candidate set to top 5
        and truncating text snippets to 350 chars.
        """
        if not hits:
            return []
            
        self._ensure_loaded()
        if not self.model:
            logger.warning("Reranker model is not loaded. Returning original hits limited to top_n.")
            return hits[:top_n]

        try:
            # Evaluate top 15 candidates with generous text snippet (1200 chars) so pricing, SKU, and instructions are preserved
            target_hits = hits[:15]
            pairs = []
            for hit in target_hits:
                meta = hit.get("metadata", {})
                product_name = meta.get("product_name") or meta.get("title")
                if not product_name:
                    source_file = meta.get("source_file", "unknown")
                    product_name = source_file
                    for ext in [".pdf", ".docx", ".txt", "_parsed.json"]:
                        product_name = product_name.replace(ext, "")
                    product_name = product_name.replace("-", " ").replace("_", " ").strip()
                
                section = meta.get("section", "General")
                text = hit.get("text", "")[:1200]
                
                enriched_text = f"Product: {product_name} | Section: {section} | Content: {text}"
                pairs.append([query, enriched_text])
            
            import torch
            with torch.no_grad():
                scores = self.model.predict(pairs, batch_size=8, show_progress_bar=False)
            
            import math
            reranked_hits = []
            for hit, raw_score in zip(target_hits, scores):
                updated_hit = hit.copy()
                val = float(raw_score)
                norm_score = 1.0 / (1.0 + math.exp(-val)) if -700 <= val <= 700 else (1.0 if val > 700 else 0.0)
                updated_hit["rerank_score"] = norm_score
                reranked_hits.append(updated_hit)
                
            sorted_hits = sorted(reranked_hits, key=lambda h: h["rerank_score"], reverse=True)
            
            logger.info(f"Successfully reranked {len(target_hits)} candidates. Top score: {sorted_hits[0]['rerank_score']:.4f}")
            return sorted_hits[:top_n]
        except Exception as e:
            logger.error(f"Reranking failed: {e}. Falling back to original rankings.")
            return hits[:top_n]


# --- Prompt Context Builder ---
class PromptContextBuilder:
    @staticmethod
    def build_context(hits: List[Dict[str, Any]]) -> str:
        """
        Builds a structured, numbered context string with source file, page, 
        section headers, and promotional period (if any) to pass into the LLM prompt.
        """
        if not hits:
            return "No relevant context found."

        context_parts = []
        total_chars = 0
        MAX_CONTEXT_CHARS = 20000  # ~5,000 tokens budget reserved for context (OpenAI GPT-5.4)

        for idx, hit in enumerate(hits, start=1):
            metadata = hit.get("metadata", {})
            source_file = metadata.get("source_file", "unknown")
            product_name = metadata.get("product_name") or metadata.get("title") or metadata.get("treatment_name")
            if not product_name:
                product_name = os.path.splitext(source_file)[0].replace("-", " ").replace("_", " ").strip()

            doc_type = metadata.get("document_type", "GENERAL")
            category = metadata.get("category") or (metadata.get("categories")[0] if metadata.get("categories") else "")
            cat_header = f" | Category: {category}" if category else ""

            rel_prods = metadata.get("related_products", [])
            rel_prods_header = f" | Related Products: {', '.join(rel_prods[:4])}" if rel_prods else ""

            rel_treats = metadata.get("related_treatments", [])
            rel_treats_header = f" | Related Treatments: {', '.join(rel_treats[:4])}" if rel_treats else ""

            indications = metadata.get("indications", [])
            ind_header = f" | Indications: {', '.join(indications[:5])}" if indications else ""

            section = metadata.get("section", "General")
            page = metadata.get("page", 1)
            image_url = metadata.get("image_url") or metadata.get("image")
            if not image_url and metadata.get("image_urls") and isinstance(metadata.get("image_urls"), list) and len(metadata["image_urls"]) > 0:
                image_url = metadata["image_urls"][0]
            text = hit.get("text", "")
            if not image_url:
                img_matches = re.findall(r'!\[.*?\]\(([^\)]+)\)', text)
                if img_matches:
                    image_url = img_matches[0]

            # Smart chunk trimming: limit individual chunk text to 1,400 chars (~350 tokens) to ensure room for multiple documents
            if len(text) > 1400:
                text = text[:1400] + "\n... [bagian detail dipadatkan]"

            valid_from = metadata.get("valid_from")
            valid_until = metadata.get("valid_until")
            promo_header = ""
            if valid_until or valid_from:
                if valid_from and valid_until:
                    promo_header = f" | Periode Promo: {valid_from} s/d {valid_until}"
                elif valid_until:
                    promo_header = f" | Berlaku Hingga: {valid_until}"

            sku = metadata.get("sku")
            sku_header = f" | SKU: {sku}" if sku else ""
            price = metadata.get("price")
            price_header = f" | Price: {price}" if price else ""

            kid = metadata.get("knowledge_id") or source_file
            id_header = f"ID: {kid} | " if kid else ""
            img_header = f" | Image: {image_url}" if image_url else ""
            part = (
                f"[{idx}] {id_header}Type: {doc_type} | Title: {product_name}{cat_header}{sku_header}{price_header}{ind_header}{promo_header}{img_header}{rel_prods_header}{rel_treats_header} | Section: {section} | Source: {source_file}\n"
                f"Content:\n{text.strip()}"
            )

            # Token Budget Check: Stop adding chunks if total context exceeds token budget
            if total_chars + len(part) > MAX_CONTEXT_CHARS and context_parts:
                logger.info(f"Token Budget Reached: Context capped at {idx-1} chunks ({total_chars} chars, ~{total_chars//4} tokens).")
                break

            context_parts.append(part)
            total_chars += len(part)

        return "\n\n".join(context_parts)


# --- Helper Rank Functions ---
def get_chunk_key(hit: Dict[str, Any]) -> str:
    meta = hit.get("metadata", {})
    source_file = meta.get("source_file")
    chunk_index = meta.get("chunk_index")
    if source_file is not None and chunk_index is not None:
        return f"{source_file}_{chunk_index}"
    return str(hash(hit.get("text", "")))

# --- Clinical Synonym & Slang Dictionary ---
CLINICAL_SYNONYM_DICTIONARY = {
    "bruntusan": ["comedonal acne", "closed comedones", "komedo tertutup", "sumbatan pori"],
    "komedoan": ["comedones", "blackhead", "whitehead", "komedo terbuka tertutup"],
    "bopeng": ["atrophic acne scar", "acne scar", "bopeng bekas jerawat", "microneedling"],
    "scar": ["atrophic acne scar", "acne scar", "bekas jerawat"],
    "flek": ["hyperpigmentation", "melasma", "PIH", "flek hitam"],
    "flek hitam": ["melasma", "hyperpigmentation", "PIH", "lentigo"],
    "kusam": ["dull skin", "brightening", "kulit kusam", "regenerasi kulit"],
    "mendem": ["cystic acne", "nodular acne", "jerawat meradang kistik"],
    "jerawat batu": ["cystic acne", "nodul kistik", "inflammatory acne berat"],
    "kebal": ["acne resistant", "keratolytic", "peeling"],
    "badak": ["acne resistant", "keratolytic", "peeling kuat"],
    "merah": ["erythema", "post acne erythema", "PAE", "inflamasi kemerahan"],
    "meradang": ["inflammatory acne", "papule", "pustule", "lesi inflamasi"],
    "pori gede": ["enlarged pores", "pori pori besar", "seborrhea"],
    "pori besar": ["enlarged pores", "pori pori besar", "sebum oily"],
    "minyakan": ["sebum oily", "kulit berminyak", "excess sebum", "oil control"],
    "sabun": ["facial wash", "cleanser", "pembersih wajah"],
    "sabun muka": ["gentle acne facial wash", "cleanser", "pembersih wajah"],
    "totol": ["acne spot gel", "spot treatment", "totol jerawat"],
    "krim malam": ["night cream", "retinol", "moisturizer malam"],
    "krim siang": ["day cream", "sunscreen", "moisturizer pagi"],
    "sunscreen": ["tabir surya", "SPF50", "sun protection", "sunblock"],
    "tahapan": ["tahapan treatment", "prosedur tindakan", "protokol perawatan", "langkah treatment"],
    "tahapan treatment": ["prosedur tindakan", "tahapan perawatan", "langkah treatment", "protokol klinis"],
    "prosedur": ["tahapan tindakan", "protokol perawatan", "prosedur medis", "clinical procedure"],
}

def expand_clinical_query(query: str) -> str:
    """Expands doctor slang and informal bilingual terms with standard clinical vocabulary."""
    if not query:
        return query
    q_lower = query.lower()
    expanded_terms = []
    for term, syns in CLINICAL_SYNONYM_DICTIONARY.items():
        pattern = r'\b' + re.escape(term) + r'\b'
        if re.search(pattern, q_lower):
            expanded_terms.extend(syns[:2])

    if expanded_terms:
        unique_syns = list(dict.fromkeys(expanded_terms))
        return f"{query} {' '.join(unique_syns[:8])}"
    return query


def reciprocal_rank_fusion(
    dense_hits: List[Dict[str, Any]], 
    sparse_hits: List[Dict[str, Any]], 
    rrf_k: int = 60,
    dense_weight: float = 1.0,
    sparse_weight: float = 1.0
) -> List[Dict[str, Any]]:
    rrf_scores = {}

    for rank, hit in enumerate(dense_hits, start=1):
        key = get_chunk_key(hit)
        if key not in rrf_scores:
            rrf_scores[key] = {"hit": hit, "score": 0.0}
        rrf_scores[key]["score"] += dense_weight * (1.0 / (rrf_k + rank))

    for rank, hit in enumerate(sparse_hits, start=1):
        key = get_chunk_key(hit)
        if key not in rrf_scores:
            rrf_scores[key] = {"hit": hit, "score": 0.0}
        rrf_scores[key]["score"] += sparse_weight * (1.0 / (rrf_k + rank))

    sorted_keys = sorted(rrf_scores.keys(), key=lambda k: rrf_scores[k]["score"], reverse=True)

    fused_hits = []
    for key in sorted_keys:
        merged_hit = rrf_scores[key]["hit"].copy()
        merged_hit["rrf_score"] = rrf_scores[key]["score"]
        merged_hit["score"] = rrf_scores[key]["score"]
        fused_hits.append(merged_hit)

    return fused_hits


# --- Hybrid Retriever ---
class HybridRetriever:
    def __init__(
        self, 
        vector_store: BaseVectorStoreAdapter, 
        bm25_index: BM25Index,
        reranker: Optional[Reranker] = None
    ):
        self.vector_store = vector_store
        self.bm25_index = bm25_index
        self.reranker = reranker

    def retrieve(
        self, 
        query: str, 
        top_k: int = 8, 
        filter_metadata: Optional[Dict[str, Any]] = None,
        rerank: bool = True,
        rerank_top_n: int = 6,
        confidence_threshold: Optional[float] = None,
        include_expired: bool = False
    ) -> Dict[str, Any]:
        """
        Executes Advanced Retrieval Pipeline:
        1. Clinical Synonym & Slang Expansion
        2. Dynamic Hybrid Router (Alpha Weight Tuning)
        3. Parallel Dense (PGVector) & Sparse (BM25)
        4. Reciprocal Rank Fusion (RRF) with weighted alpha
        5. Temporal Validity Filtering
        6. Cross-Encoder Reranking with Clinical Indication Boost
        """
        # 1. Clinical Query Expansion
        expanded_query = expand_clinical_query(query)
        if expanded_query != query:
            logger.info(f"🔍 [Query Expansion] '{query}' -> '{expanded_query}'")
        else:
            logger.debug(f"Retrieving for query: '{query}' with top_k={top_k}")

        # 2. Dynamic Hybrid Router (Alpha Weight Tuning)
        q_lower = query.lower()
        exact_indicators = ["sku", "harga", "berapa", "kandungan", "komposisi", "nama produk", "kode", "brand", "netto", "isi"]
        is_exact_lookup = any(ind in q_lower for ind in exact_indicators)

        if is_exact_lookup:
            dense_weight = 0.7
            sparse_weight = 1.3
            logger.debug("🎯 [Dynamic Router] Exact lookup detected -> Boosting BM25 sparse weight (1.3)")
        else:
            dense_weight = 1.2
            sparse_weight = 0.8
            logger.debug("🩺 [Dynamic Router] Clinical query detected -> Boosting PGVector dense weight (1.2)")

        candidate_k = top_k * 2

        import concurrent.futures
        with concurrent.futures.ThreadPoolExecutor(max_workers=2) as executor:
            future_dense = executor.submit(self.vector_store.search, expanded_query, candidate_k, filter_metadata) if self.vector_store else None
            future_sparse = executor.submit(self.bm25_index.search, expanded_query, candidate_k, filter_metadata, include_expired) if self.bm25_index else None
            
            dense_hits = future_dense.result() if future_dense else []
            sparse_hits = future_sparse.result() if future_sparse else []

        if self.vector_store:
            logger.debug(f"Dense retrieval returned {len(dense_hits)} candidates.")
        if self.bm25_index:
            logger.debug(f"Sparse retrieval returned {len(sparse_hits)} candidates.")
        
        fused_hits = reciprocal_rank_fusion(dense_hits, sparse_hits, dense_weight=dense_weight, sparse_weight=sparse_weight)
        logger.debug(f"RRF Fusion completed. Fused {len(fused_hits)} candidates.")

        # Deduplicate
        seen_texts = set()
        deduplicated_hits = []
        for hit in fused_hits:
            text = hit.get("text", "").strip()
            norm_text = " ".join(text.split()).lower()
            if norm_text not in seen_texts:
                seen_texts.add(norm_text)
                deduplicated_hits.append(hit)
        logger.debug(f"Deduplicated fused hits from {len(fused_hits)} to {len(deduplicated_hits)} unique candidates.")

        # Temporal filtering: exclude expired promotional chunks when include_expired=False
        today = datetime.now(timezone.utc).date()
        active_hits = []
        for hit in deduplicated_hits:
            meta = hit.get("metadata", {})
            if is_chunk_valid_temporal(meta, current_date=today, include_expired=include_expired):
                active_hits.append(hit)
            else:
                p_name = meta.get("product_name") or meta.get("source_file", "unknown")
                vu = meta.get("valid_until") or meta.get("expiry_date")
                logger.info(f"Filtered out expired promotional chunk: '{p_name}' (valid_until: {vu})")

        # Target ingredient extraction for precision filtering & anti-contamination
        target_ingredient = None
        ing_match = re.search(r'\b(?:kandungan|mengandung|bahan\s+aktif|komposisi|ingredients?|dengan\s+kandungan)\s+([a-zA-Z0-9\-\s]{3,30})\b', q_lower)
        if ing_match:
            cand = ing_match.group(1).strip()
            cand = re.sub(r'\b(apa\s+saja|adakah|ada|saja|ya|dong|tolong|di\s+erha|ini|itu|tersebut)\b', '', cand).strip()
            if re.match(r'^(dan|atau|serta|pada|dari|dalam|tentang|apakah|bagaimana)\b', cand):
                cand = ""
            if len(cand) >= 3 and cand not in ("produk", "skincare", "obat", "cream", "krim", "serum"):
                target_ingredient = cand
        elif re.search(r'\bproduk\s+([a-zA-Z0-9\-]{4,25})\b', q_lower):
            prod_cand = re.search(r'\bproduk\s+([a-zA-Z0-9\-]{4,25})\b', q_lower).group(1).strip()
            if any(prod_cand.endswith(suf) for suf in ["ine", "ide", "acid", "ol", "ate", "oil"]) or prod_cand in ("centella", "retinol", "ceramide", "niacinamide", "betaine", "salicylic", "glycolic", "hyaluronic"):
                target_ingredient = prod_cand

        if target_ingredient:
            target_ing_lower = target_ingredient.lower()
            matching_active = []
            for h in active_hits:
                txt = h.get("text", "").lower()
                meta_str = str(h.get("metadata", {})).lower()
                if target_ing_lower in txt or target_ing_lower in meta_str:
                    h["_has_target_ingredient"] = True
                    matching_active.append(h)
                else:
                    h["_has_target_ingredient"] = False
            if matching_active:
                logger.info(f"Target ingredient '{target_ingredient}' matched {len(matching_active)} chunks in pre-filtering.")
                active_hits = matching_active

        final_hits = active_hits
        if rerank and self.reranker and active_hits:
            all_reranked = self.reranker.rerank(query, active_hits, top_n=len(active_hits))
            
            query_lower = query.lower()
            usage_keywords = ["how to use", "directions", "cara pakai", "cara penggunaan", "aturan pakai", "dosis", "instruksi"]
            procedure_keywords = ["tahapan", "tahap", "prosedur", "protokol", "langkah", "step", "alur", "cara tindakan"]
            ingredients_keywords = ["kandungan", "ingredients", "bahan aktif", "komposisi", "active ingredients"]
            treatment_keywords = ["treatment", "tindakan", "prosedur", "perawatan", "peeling", "ekstraksi", "facial", "terapi", "laser"]
            product_keywords = ["produk", "skincare", "serum", "krim", "cream", "facial wash", "cleanser", "sunscreen", "moisturizer", "sku"]

            is_usage_intent = any(k in query_lower for k in usage_keywords)
            is_procedure_intent = any(k in query_lower for k in procedure_keywords)
            is_ingredients_intent = any(k in query_lower for k in ingredients_keywords)
            is_treatment_intent = any(k in query_lower for k in treatment_keywords)
            is_product_intent = any(k in query_lower for k in product_keywords)

            # Target ingredient extraction for precision filtering & anti-contamination
            target_ingredient = None
            ing_match = re.search(r'\b(?:kandungan|mengandung|bahan\s+aktif|komposisi|ingredients?|dengan\s+kandungan)\s+([a-zA-Z0-9\-\s]{3,30})\b', query_lower)
            if ing_match:
                cand = ing_match.group(1).strip()
                cand = re.sub(r'\b(apa\s+saja|adakah|ada|saja|ya|dong|tolong|di\s+erha|ini|itu|tersebut)\b', '', cand).strip()
                if re.match(r'^(dan|atau|serta|pada|dari|dalam|tentang|apakah|bagaimana)\b', cand):
                    cand = ""
                if len(cand) >= 3 and cand not in ("produk", "skincare", "obat", "cream", "krim", "serum"):
                    target_ingredient = cand
            elif re.search(r'\bproduk\s+([a-zA-Z0-9\-]{4,25})\b', query_lower):
                prod_cand = re.search(r'\bproduk\s+([a-zA-Z0-9\-]{4,25})\b', query_lower).group(1).strip()
                if any(prod_cand.endswith(suf) for suf in ["ine", "ide", "acid", "ol", "ate", "oil"]) or prod_cand in ("centella", "retinol", "ceramide", "niacinamide", "betaine", "salicylic", "glycolic", "hyaluronic"):
                    target_ingredient = prod_cand

            # Clinical indication keywords for automatic medical cross-referencing
            clinical_indications_query = []
            indication_kw_map = {
                "acne_vulgaris": ["acne", "jerawat", "papul", "pustul", "meradang", "bruntusan", "acne vulgaris"],
                "comedones": ["komedo", "blackhead", "whitehead", "pori tersumbat"],
                "acne_scar": ["bekas jerawat", "scar", "bopeng", "boxcar", "rolling scar"],
                "sebum_oily": ["berminyak", "oily", "minyak", "sebum"],
                "hyperpigmentation": ["flek", "noda hitam", "dark spot", "melasma", "pih", "hiperpigmentasi"],
                "dull_skin": ["kusam", "mencerahkan", "brightening", "glowing", "warna kulit tidak merata"],
                "aging_wrinkles": ["aging", "penuaan", "kerutan", "garis halus", "keriput"],
                "sensitive_barrier": ["sensitif", "kemerahan", "iritasi", "skin barrier", "inflamasi"]
            }
            for ind_key, kws in indication_kw_map.items():
                if any(kw in query_lower for kw in kws):
                    clinical_indications_query.append(ind_key)

            boosted_hits = []
            for hit in all_reranked:
                updated_hit = hit.copy()
                meta = updated_hit.get("metadata", {})
                section_upper = meta.get("section", "").upper()
                doc_type_upper = str(meta.get("document_type", "")).upper()
                boost = 0.0
                
                if is_usage_intent and any(s in section_upper for s in ["HOW TO USE", "DIRECTIONS", "CARA PAKAI"]):
                    boost += 0.05
                elif is_ingredients_intent and any(s in section_upper for s in ["INGREDIENT", "KANDUNGAN", "KOMPOSISI"]):
                    boost += 0.05

                # Strict ingredient match boost (+0.35)
                if target_ingredient:
                    target_ing_lower = target_ingredient.lower()
                    hit_text_lower = updated_hit.get("text", "").lower()
                    meta_lower = str(meta).lower()
                    if target_ing_lower in hit_text_lower or target_ing_lower in meta_lower:
                        boost += 0.35
                        updated_hit["_has_target_ingredient"] = True
                        logger.debug(f"Target ingredient '{target_ingredient}' found in '{meta.get('product_name')}'. Boosted +0.35")
                    else:
                        updated_hit["_has_target_ingredient"] = False

                if is_procedure_intent and any(s in section_upper for s in ["TAHAPAN", "PROSEDUR", "PROTOKOL", "LANGKAH", "INFORMASI PROSEDUR", "CARA TINDAKAN"]):
                    boost += 0.15
                    
                if is_treatment_intent and (doc_type_upper == "TREATMENT" or any(s in section_upper for s in ["TREATMENT", "PERAWATAN", "TINDAKAN", "PROSEDUR", "PROTOKOL"])):
                    boost += 0.10
                elif is_product_intent and (doc_type_upper == "PRODUCT" or any(s in section_upper for s in ["PRODUCT", "PRODUK", "KATALOG", "SKINCARE"])):
                    boost += 0.05

                # Auto-Cross-Reference: Clinical Indication Match Boost (+0.12)
                hit_indications = meta.get("indications", [])
                if clinical_indications_query and hit_indications:
                    shared_inds = set(clinical_indications_query).intersection(set(hit_indications))
                    if shared_inds:
                        boost += 0.12
                        logger.debug(f"Applied clinical indication boost +0.12 for {shared_inds} to '{meta.get('product_name')}'")

                if boost > 0:
                    updated_hit["rerank_score"] = updated_hit.get("rerank_score", 0.0) + boost
                    logger.debug(f"Applied total boost of +{boost:.2f} to section '{section_upper}' / doc_type '{doc_type_upper}' (new score: {updated_hit['rerank_score']:.4f})")
                boosted_hits.append(updated_hit)

            # Document Diversity Selection:
            # Prevents a single document from dominating all top-N slots so interrelated documents (e.g. Treatment + Product + Promo) can both be retrieved
            sorted_by_score = sorted(boosted_hits, key=lambda h: h.get("rerank_score", 0.0), reverse=True)

            # Strict ingredient isolation: if target ingredient is requested and we have matching hits,
            # discard non-matching product hits so unrelated products don't leak into the context
            if target_ingredient:
                matching_hits = [h for h in sorted_by_score if h.get("_has_target_ingredient")]
                if matching_hits:
                    logger.info(f"Target ingredient '{target_ingredient}' matched {len(matching_hits)} chunks. Discarding non-matching products to prevent leakage.")
                    sorted_by_score = matching_hits
            diverse_hits = []
            seen_doc_counts = {}
            deferred_hits = []
            max_per_doc = 3 if is_procedure_intent else 2

            for hit in sorted_by_score:
                meta = hit.get("metadata", {})
                doc_key = meta.get("source_file") or meta.get("knowledge_id") or "unknown"
                count = seen_doc_counts.get(doc_key, 0)
                if count < max_per_doc:
                    diverse_hits.append(hit)
                    seen_doc_counts[doc_key] = count + 1
                else:
                    deferred_hits.append(hit)
                if len(diverse_hits) >= rerank_top_n:
                    break

            # If diverse slots are not full, backfill from deferred hits
            if len(diverse_hits) < rerank_top_n:
                for hit in deferred_hits:
                    diverse_hits.append(hit)
                    if len(diverse_hits) >= rerank_top_n:
                        break

            final_hits = diverse_hits
            logger.debug(f"Reranking and Document Diversity Selection completed. Returned {len(final_hits)} chunks across {len(seen_doc_counts)} documents.")
        else:
            final_hits = active_hits[:top_k]

        threshold = confidence_threshold if confidence_threshold is not None else settings.rerank_confidence_threshold
        if rerank and self.reranker and final_hits:
            max_score = final_hits[0].get("rerank_score", 0.0)
            if max_score < threshold:
                logger.warning(f"Retrieval confidence score {max_score:.4f} is below threshold {threshold:.4f}. Rejecting retrieved context.")
                return {
                    "query": query,
                    "results": [],
                    "context": "Maaf, saya tidak menemukan informasi."
                }

        context_string = PromptContextBuilder.build_context(final_hits)

        return {
            "query": query,
            "results": final_hits,
            "context": context_string
        }
