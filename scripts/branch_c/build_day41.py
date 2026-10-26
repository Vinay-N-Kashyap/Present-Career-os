import json
import hashlib
import re

part1_say = [
    "To architect modern enterprise intelligence engines capable of synthesizing knowledge across millions of documents, AI systems engineers must master the fundamental mechanics and architectural limitations of dense vector retrieval. In first-generation generative search pipelines, information retrieval was dominated by lexical matching algorithms like BM25 and TF-IDF, which scored document relevance based on exact keyword occurrences and inverse document frequencies. While lexical search excels at matching rare identifiers—such as part serial numbers or legal statute citations—it fails completely when queries and documents express identical semantic concepts using divergent vocabulary.",
    "To bridge this semantic vocabulary mismatch, modern neural information retrieval adopted dense vector representations powered by Siamese transformer architectures, universally known as Bi-Encoders. Popularized by frameworks like Sentence-BERT and Dense Passage Retrieval (DPR), the Bi-Encoder decouples the ingestion of queries from documents. A dedicated query encoder maps incoming search queries into a fixed-dimensional vector space, while an identical or mirrored document encoder maps text passages into the same shared representation space.",
    "The core operational advantage of the Bi-Encoder paradigm lies in asynchronous indexing efficiency. Because document representations depend exclusively on document text, millions of corpus passages can be encoded offline in background batch jobs. The resulting dense vectors (typically seven hundred sixty-eight or one thousand five hundred thirty-six floating-point numbers) are loaded into specialized approximate nearest neighbor (ANN) vector databases such as Milvus, Qdrant, or Pinecone, indexed via Hierarchical Navigable Small World (HNSW) graphs or Inverted File with Product Quantization (IVF-PQ).",
    "At query execution time, the online latency budget is minimal: the incoming user query passes through the query encoder in a single forward pass, producing a solitary dense vector q. Retrieval reduces to computing inner products or cosine similarities between q and millions of pre-computed document vectors d, a mathematical operation accelerated via highly optimized SIMD instructions and GPU matrix multiplication kernels.",
    "Mathematically, the similarity score between query q and document d is formulated as the dot product or cosine similarity: score equals q dot d divided by the product of their Euclidean norms. When vectors are L2-normalized during embedding generation, cosine similarity simplifies into a pure inner product, executing billions of vector evaluations per second across distributed server clusters.",
    "However, this decoupling comes at an immense architectural cost: zero token-level interaction during encoding. Because the query and document encoders operate in complete isolation without cross-attention, the model must compress the entire semantic nuance of a multi-sentence passage into a single solitary coordinate vector before observing the user's specific information need.",
    "A physical analogy clarifies this fundamental trade-off: sending an investigator into a massive corporate library with instructions to summarize every three-hundred-page volume onto a single three-by-five index card before any question has been asked. When an executive later asks a highly specific question about an obscure footnote on page two hundred fourteen, the investigator must rely entirely on whatever coarse summary survived the index card compression, inevitably missing subtle technical details.",
    "In high-dimensional representation geometry, mapping complex heterogeneous documents to solitary vectors also triggers the curse of dimensionality. Within a unit hypersphere, random vectors become near-orthogonal, forcing disparate semantic facts within a single document to compete for representational volume, creating severe vector congestion.",
    "Furthermore, Bi-Encoders are vulnerable to domain shifts: an embedding model trained on general web corpora frequently fails when deployed on specialized biomedical literature or proprietary corporate codebases, where domain-specific nomenclature is misinterpreted as generic noise.",
    "From a systems performance standpoint, scaling Bi-Encoder deployments across large enterprise datasets requires dedicated vector indexing infrastructure. Approximate nearest neighbor algorithms construct high-dimensional proximity graphs that trade small percentages of recall accuracy for logarithmic search latency, enabling real-time query response times under high-concurrency production workloads.",
    "This fundamental separation between query and document representations establishes the Bi-Encoder as an exceptional coarse-grained filtering engine, but leaves it severely ill-equipped to resolve complex multi-hop queries, fine-grained entity relationships, or exact numerical conditions."
]

part2_say = [
    "To understand why dense Bi-Encoders frequently fail on fine-grained factual retrieval in enterprise applications, systems engineers must analyze the severe information bottleneck imposed by vector pooling. In modern transformer architectures, an input passage of length N tokens generates N distinct contextualized hidden state vectors, each of dimension d. A five-hundred-token passage processed by a model with hidden dimension seven hundred sixty-eight generates three hundred ninety-three thousand two hundred sixteen floating-point values representing rich syntactic, semantic, and relational information.",
    "To produce a single vector for Bi-Encoder retrieval, this high-dimensional tensor must be collapsed into a solitary vector of size d (seven hundred sixty-eight floats). This collapse is executed via pooling operators, primarily Mean Pooling—which computes the element-wise average across all N token vectors—or CLS Token Pooling, which extracts the representation of the leading classification token.",
    "Mathematically, this pooling operation represents a five-hundred-fold information compression bottleneck: three hundred ninety-three thousand floating-point values are violently flattened into seven hundred sixty-eight values. In information theory, compressing a high-dimensional multivariate distribution into a lower-dimensional subspace inevitably destroys fine-grained mutual information, retaining only the dominant, high-entropy themes of the passage while obliterating delicate token-level dependencies.",
    "This pooling bottleneck causes the fatal phenomenon of Vector Smearing. When a passage discusses three distinct concepts—such as a pharmaceutical clinical trial evaluating drug efficacy, adverse cardiac side effects, and patient demographic exclusion criteria—mean pooling blends these orthogonal semantic topics into an average centroid vector. The resulting pooled vector represents a blurred composite that matches moderately well with generic queries about clinical trials, but fails to trigger strong similarity matches for specific queries seeking exact exclusionary criteria.",
    "Furthermore, vector pooling destroys entity-relation bindings. In high-dimensional transformer layers, cross-attention binds entities to their attributes: the drug name is bound to its exact dosage, and the adverse effect is bound to its incidence percentage. Collapsing these bindings via mean pooling decouples attributes from entities, causing the Bi-Encoder to treat 'Drug A cured Condition B with 10% side effect C' as mathematically identical to 'Drug C cured Condition A with 10% side effect B'.",
    "A geometric analysis of cosine similarity in pooled spaces reveals severe angular distortion: as passage length grows, the pooled vector drifts toward the geometric center of the embedding manifold, reducing its angular separation from unrelated documents and triggering high false-positive retrieval rates under dense multi-tenant search workloads.",
    "In mathematical optimization, training Bi-Encoders with InfoNCE contrastive loss attempts to mitigate this by maximizing the inner product of positive query-passage pairs while pushing negative passages away. However, contrastive training on solitary pooled vectors cannot overcome the physical limits of vector capacity: a seven-hundred-sixty-eight-dimensional vector lacks the geometric degrees of freedom required to store dozens of independent relational facts simultaneously.",
    "Empirical evaluations on technical documentation benchmarks demonstrate this failure mode vividly: when presented with a query requiring an exact configuration flag, a pooled Bi-Encoder frequently retrieves a general introductory overview of the software module rather than the specific paragraph containing the required syntax, because the broad overview has higher overall semantic overlap with the query.",
    "In enterprise financial auditing and legal discovery, this pooling failure is especially catastrophic: financial statements contain dense tabular matrices where a single inverted sign or shifted decimal completely reverses the economic meaning of a passage. When collapsed via vector pooling, these precise quantitative relations are smoothed out, causing the Bi-Encoder to treat financially divergent quarterly reports as semantically equivalent, introducing severe operational risk.",
    "Consequently, treating pooled dense vectors as the sole representation of complex corporate knowledge bases introduces an insurmountable fidelity ceiling, forcing systems architects to seek multi-vector architectures that preserve token-level granularity.",
    "This information bottleneck demonstrates that while vector pooling is computationally convenient for high-speed indexing, it sacrifices the precise relational fidelity required for autonomous enterprise intelligence."
]

part3_say = [
    "To rigorously quantify and compare the capabilities of dense embedding models across diverse semantic tasks, the AI research community established the Massive Text Embedding Benchmark, universally designated as MTEB. Spanning dozens of datasets across multiple operational tasks—including document retrieval, semantic textual similarity (STS), classification, clustering, pair classification, and reranking—MTEB has become the definitive global leaderboard governing embedding model selection.",
    "Analyzing MTEB benchmark results reveals a critical engineering insight: superior performance on Semantic Textual Similarity does not guarantee superior performance on document retrieval. In Semantic Textual Similarity benchmarks, models evaluate whether two short, symmetric sentences (such as 'The cat sat on the mat' and 'A feline rested on the rug') share identical meaning. In contrast, document retrieval is fundamentally asymmetric: a short, ambiguous user query must retrieve a long, structured technical document.",
    "Foundation models optimized primarily for symmetric sentence similarity often perform poorly on enterprise retrieval because their embedding spaces are trained to maximize semantic paraphrase alignment rather than asymmetric question-answer relevance. When evaluated on the BEIR (Benchmarking Information Retrieval) subset of MTEB, models with stellar STS scores frequently degrade on technical domains like BioASQ (biomedical QA), FiQA (financial analysis), and ClimateFEVER (scientific fact-checking).",
    "A primary driver of this discrepancy is the quality and distribution of training negatives. In contrastive representation learning, models learn by distinguishing the true positive document from candidate negative documents. Naive training utilizing random in-batch negatives teaches the model to separate wildly different topics (such as separating medicine from sports) but fails to teach the model how to distinguish between two subtly different pharmaceutical patents.",
    "State-of-the-art embedding models on the MTEB leaderboard—such as voyage-large-2, text-embedding-3-large, and bge-large-en-v1.5—overcome this through Hard Negative Mining. Advanced data generation pipelines mine challenging lexical negatives using BM25 and cross-encoder score thresholding, forcing the Bi-Encoder to map subtle semantic differences into distinct angular sectors of the embedding space.",
    "Furthermore, MTEB benchmarks reveal the impact of embedding dimension scaling. Scaling dimensions from three hundred eighty-four to one thousand five hundred thirty-six or three thousand seventy-two provides modest accuracy improvements (typically two to five percentage points on NDCG@10) but imposes a linear four-to-eight-fold increase in vector database DRAM consumption and ANN search latency.",
    "In enterprise production environments, systems engineers utilize Matryoshka Representation Learning (MRL) to navigate this cost-accuracy trade-off. Matryoshka-trained models structure their hidden states hierarchically, such that truncating a one-thousand-five-hundred-thirty-six-dimensional vector down to two hundred fifty-six dimensions retains over ninety-six percent of full-dimension retrieval performance while slashing indexing storage costs by eighty-three percent.",
    "To validate embedding model robustness in production settings, enterprise platform engineers deploy automated regression test benches that measure Mean Reciprocal Rank (MRR) and Hit Rate across synthetic domain-specific challenge sets. These automated evaluation pipelines detect latent semantic drift before newly trained embedding checkpoints are rolled out to production user queries.",
    "From an operational lifecycle perspective, maintaining embedding quality requires continuous telemetry and automated canary benchmarking. When updating base foundation embedding models or fine-tuning domain adapters, platform teams must evaluate retrieval performance across representative enterprise query logs, verifying that domain-specific technical queries experience zero regression in top-k retrieval accuracy.",
    "Despite these continuous optimizations, the fundamental ceiling of MTEB retrieval scores remains bounded: even the top-ranked models on the leaderboard struggle to exceed sixty-five percent NDCG@10 on zero-shot out-of-domain technical retrieval, proving that solitary vector representations possess inherent structural limits.",
    "Understanding MTEB dynamics empowers systems architects to look beyond monolithic benchmark scores, designing multi-stage retrieval pipelines that match specialized embedding representations to distinct operational tasks.",
    "In conclusion, MTEB audits confirm that embedding models are not universal drop-in solutions: maximizing enterprise retrieval accuracy requires calibrating model architecture, dimensionality, and negative training distributions against domain-specific query characteristics."
]

part4_say = [
    "A paramount challenge in enterprise retrieval systems is Information Asymmetry: the radical structural, lexical, and semantic divergence between user queries and target knowledge documents. In typical enterprise applications, a user query is brief, telegraphic, and underspecified (averaging five to ten tokens, such as 'API rate limit error 429'), while the target documentation is extensive, structured, and formal (containing hundreds of tokens describing HTTP headers, token-bucket algorithms, and retry-after exponential backoff policies).",
    "When a standard symmetric Bi-Encoder processes this query, the query encoder extracts representations from a five-word fragment and attempts to match it against a five-hundred-word document vector. Because the document vector is dominated by detailed technical prose that has no direct lexical or syntactic counterpart in the short query, the cosine similarity between their pooled representations is severely depressed.",
    "To counteract this structural mismatch, frontier embedding architectures deploy Asymmetric Dual Encoders. In asymmetric architectures, the query encoder and document encoder are either parameterized with distinct transformer weights or conditioned on task-specific instructional prefixes (such as 'Represent this sentence for searching relevant passages:'). These prefixes steer the query vector into the semantic region occupied by comprehensive explanatory documents rather than conversational queries.",
    "However, even asymmetric Bi-Encoders fail when user queries contain exact alphanumeric strings—such as transaction IDs, error codes, function signatures, or medical drug identifiers. Because dense neural encoders prioritize high-level conceptual semantics over literal character sequences, a dense vector search for 'Error Code 429' frequently retrieves documents discussing 'Error Code 503' or general network timeouts because their semantic embeddings reside in adjacent vector clusters.",
    "To resolve this fatal blindness to exact keywords, enterprise search architectures deploy Hybrid Search Pipelines that fuse dense neural retrieval with classical lexical search (BM25). In a hybrid pipeline, the query executes simultaneously across an inverted lexical index and an approximate nearest neighbor vector index, generating two independent candidate ranked lists.",
    "The ranked lists are fused using Reciprocal Rank Fusion, universally abbreviated as RRF. Formulated as RRF score equals the summation of one divided by the quantity (sixty plus rank position) across both lexical and dense ranking lists, RRF merges sparse keyword matches with dense semantic affinities without requiring complex score normalization or calibration.",
    "Comparative evaluations across enterprise datasets confirm that hybrid BM25 plus Bi-Encoder pipelines consistently outperform standalone dense retrieval by eight to fifteen percentage points in Mean Reciprocal Rank (MRR), providing a resilient safety net for exact keyword matching.",
    "Modern enterprise retrieval platforms often incorporate automated query expansion and hypothetical document embedding (HyDE) to reduce information asymmetry. By using a generative foundation model to hallucinate a synthetic answer passage before computing vector embeddings, the query vector is expanded with rich domain vocabulary, improving its angular alignment with genuine knowledge documents.",
    "In multi-modal and cross-lingual enterprise search, information asymmetry is compounded by linguistic and structural diversity. A single enterprise query may need to retrieve technical documentation written in Japanese, architectural schematics stored as images, and financial ledgers formatted as tables. Asymmetric multi-modal projection layers map these heterogeneous modalities into shared semantic coordinates, providing unified retrieval across enterprise knowledge silos.",
    "Hardware acceleration for hybrid fusion pipelines leverages asynchronous worker pools: lexical inverted index queries run across multi-core CPU clusters optimized for high-throughput memory mapping, while dense vector ANN searches execute in parallel on dedicated GPU inference instances. Fusing the resulting candidate lists via Reciprocal Rank Fusion introduces less than three milliseconds of total orchestration overhead.",
    "Yet, hybrid fusion remains an engineering workaround rather than a fundamental architectural solution: it combines two independent, flawed rankers rather than enabling the neural model itself to perform fine-grained token-level matching across the entire document horizon.",
    "Analyzing this information asymmetry underscores the necessity of next-generation retrieval models that combine the conceptual breadth of dense vectors with the pinpoint precision of token-level alignment.",
    "Ultimately, overcoming information asymmetry requires architectural paradigms that can cross-reference query tokens directly against document tokens without compressing either representation into a monolithic coordinate."
]

part5_say = [
    "To achieve the theoretical maximum retrieval accuracy in neural information retrieval, researchers deploy Cross-Encoders. Unlike Bi-Encoders which encode queries and documents in isolation, a Cross-Encoder feeds the query and document simultaneously into a single unified transformer model, concatenating them as [CLS] query [SEP] document [SEP].",
    "The defining architectural superpower of the Cross-Encoder is unrestricted full cross-attention. At every single transformer layer, every query token directly attends to every document token, and every document token attends to every query token. The attention projection matrices evaluate pairwise token interactions across all intermediate hidden layers, allowing the network to compute rich contextual alignments, resolve exact entity-attribute bindings, and detect subtle factual contradictions.",
    "When evaluated on benchmark retrieval datasets, Cross-Encoders achieve astonishing accuracy: on the MS-MARCO and BEIR benchmarks, Cross-Encoder models outperform Bi-Encoder architectures by over twenty to thirty percentage points in NDCG@10, setting the absolute gold standard for semantic relevance and factual fidelity.",
    "However, this supreme accuracy encounters an insurmountable computational barrier: the Quadratic Computational Cost of Full Cross-Attention. While a Bi-Encoder can pre-compute and index document vectors offline, a Cross-Encoder cannot compute any representation until the query is known at runtime. To search a corpus of one million documents using a Cross-Encoder, the system must execute one million full transformer forward passes over concatenated query-document sequences for every single user search.",
    "Across a thirty-two-layer foundation model, executing one million forward passes consumes minutes to hours of GPU execution time, destroying real-time interactive search and bankrupting enterprise latency budgets that demand responses in less than one hundred milliseconds. Cross-Encoders are physically impossible to deploy as first-stage retrieval engines over large-scale corporate corpora.",
    "In current enterprise architectures, Cross-Encoders are relegated to the second stage of retrieval: the Re-Ranking Stage. A high-speed Bi-Encoder or hybrid BM25 pipeline retrieves the top one hundred candidate documents in tens of milliseconds, and a Cross-Encoder re-ranks only these one hundred candidates, evaluating full cross-attention over a restricted candidate pool.",
    "While this two-stage pipeline is widely adopted, it suffers from a fatal architectural flaw known as Candidate Recall Bottleneck: if the first-stage Bi-Encoder fails to include the true relevant document in its top one hundred candidates—due to vector smearing or pooling loss—the Cross-Encoder never sees the document, and the retrieval pipeline fails completely.",
    "In high-throughput multi-tenant production architectures, candidate recall ceilings represent the primary constraint on end-to-end question answering fidelity. No matter how sophisticated downstream generative models or Cross-Encoder re-rankers are, they are entirely blind to evidence omitted by the initial Bi-Encoder pass, making high-recall first-stage retrieval the paramount architectural objective.",
    "Modern production architectures balance this trade-off by dynamically sizing the candidate pool based on query latency budgets and query ambiguity metrics. For straightforward navigational queries, the system routes results directly from the Bi-Encoder index, while complex analytical or multi-hop queries trigger full Cross-Encoder re-ranking over an expanded candidate set of several hundred documents, ensuring optimal resource allocation.",
    "Furthermore, rigorous cost modeling reveals that running full Cross-Encoder inference across thousands of queries costs up to fifty times more in electricity and cloud compute than running optimized vector search. This dramatic economic divergence cements the architectural consensus that enterprise search systems must reserve Cross-Encoders strictly for high-value re-ranking stages or replace them with token-level late interaction models.",
    "This fundamental operational dilemma created the urgent demand for a third paradigm: an architecture that delivers the token-level interactive fidelity of a Cross-Encoder, while retaining the sub-millisecond offline indexing and decoupled retrieval efficiency of a Bi-Encoder.",
    "This technological imperative led directly to the creation of ColBERT and Late Interaction: a revolutionary paradigm that computes token-level vector interactions after offline encoding, unlocking the next era of high-precision enterprise information retrieval.",
    "In the following lesson, we will dissect the ColBERT late interaction architecture, analyzing how token-level embeddings and the MaxSim operator bridge the gap between Bi-Encoder speed and Cross-Encoder precision."
]

code1 = """function simulateEmbeddingBottleneck(docLen: number, hiddenDim: number = 768) {
  const tokenEmbeddings = docLen * hiddenDim;
  const pooledVector = hiddenDim;
  const compressionRatio = (tokenEmbeddings / pooledVector).toFixed(1);

  // Cosine vs Dot Product on normalized representations
  const queryVec = [0.42, 0.58, 0.69];
  const docVec = [0.40, 0.60, 0.69];
  const dotProduct = queryVec.reduce((sum, q, i) => sum + q * docVec[i], 0);

  return {
    documentTokens: docLen,
    rawInformationSpaceFloats: tokenEmbeddings,
    pooledRepresentationFloats: pooledVector,
    informationCompressionLoss: `${compressionRatio}x bottleneck`,
    normalizedInnerProductScore: Number(dotProduct.toFixed(4)),
    retrievalPrecision: "Semantic coarse-grained matching only"
  };
}
console.log(simulateEmbeddingBottleneck(512));"""

output1 = """{
  documentTokens: 512,
  rawInformationSpaceFloats: 393216,
  pooledRepresentationFloats: 768,
  informationCompressionLoss: '512.0x bottleneck',
  normalizedInnerProductScore: 0.9921,
  retrievalPrecision: 'Semantic coarse-grained matching only'
}"""

# Verify word counts
parts_say = [part1_say, part2_say, part3_say, part4_say, part5_say]
for idx, p in enumerate(parts_say):
    wc = len(" ".join(p).split())
    print(f"Part {idx+1}: {wc} words")
    assert wc >= 600, f"Part {idx+1} word count too low: {wc}"
    assert len(p) >= 4, f"Part {idx+1} paragraph count too low: {len(p)}"

total_words = sum(len(" ".join(p).split()) for p in parts_say)
assert total_words >= 3100, f"Day 41 total word count too low: {total_words}"

day41_dict = {
    "day": 41,
    "title": "Dense Vector Embeddings & Bi-Encoder Limitations: MTEB, Information Asymmetry & Bottlenecks",
    "goal": "Master the mathematical foundations of dense vector embeddings, analyze the severe information bottleneck of vector pooling, audit MTEB leaderboard dynamics, and understand why Bi-Encoders fail on fine-grained factual retrieval.",
    "minutes": 38,
    "recap": "Welcome to Month 2 Block 9. Today we dissect dense vector embeddings, Siamese Bi-Encoder architectures, and the mathematical information bottlenecks that motivate multi-vector retrieval.",
    "parts": [
        {
            "title": "The Bi-Encoder Retrieval Paradigm & Siamese Networks",
            "say": part1_say,
            "example": "A library catalog card summarizes a five-hundred-page volume onto a single paper index card.",
            "code": code1,
            "output": output1,
            "tryIt": "Evaluate vector pooling compression ratios and inspect inner product similarity scores.",
            "check": {
                "question": "What is the primary operational advantage and foundational limitation of the Siamese Bi-Encoder retrieval architecture?",
                "options": [
                    "It decouples query and document encoding for sub-millisecond ANN search, but suffers from zero token-level cross-attention during encoding.",
                    "It computes full pairwise cross-attention between all query and document tokens, but requires quadratic offline storage.",
                    "It requires both query and document to be of identical token length, preventing retrieval of multi-paragraph documents.",
                    "It eliminates the need for vector databases by performing exact lexical BM25 matching inside transformer layers."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Bi-Encoders enable offline document embedding and high-speed ANN vector search, but cannot perform cross-attention between query and document tokens, forcing entire documents into a single pooled vector."
            }
        },
        {
            "title": "The Severe Information Bottleneck of Vector Pooling",
            "say": part2_say,
            "example": "Blending three distinct primary paint colors produces a muddy brown composite where original pigments cannot be separated.",
            "code": code1,
            "output": output1,
            "tryIt": "Compute the compression ratio of collapsing five hundred contextualized token vectors into a single vector.",
            "check": {
                "question": "Why does Mean Pooling or CLS Pooling trigger Vector Smearing across multi-topic corporate documents?",
                "options": [
                    "Collapsing hundreds of contextualized token vectors into a single centroid vector blends orthogonal topics and destroys fine-grained entity-relation bindings.",
                    "Mean pooling multiplies token vectors together, causing mathematical exponent overflow in deep network layers.",
                    "Pooling forces all floating-point numbers into eight-bit integers, inducing severe quantization noise.",
                    "CLS pooling discards the entire document and only encodes the first four letters of the title."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Collapsing a high-dimensional tensor into a single vector averages out orthogonal topics and obliterates delicate token-level entity-relation bindings, preventing precise factual discrimination."
            }
        },
        {
            "title": "MTEB Leaderboard Dynamics & Task Specialization",
            "say": part3_say,
            "example": "A decathlon athlete excels across ten general events but loses to specialized sprinters in high-stakes hundred-meter races.",
            "code": code1,
            "output": output1,
            "tryIt": "Analyze the divergence between Semantic Textual Similarity scores and domain-specific information retrieval accuracy.",
            "check": {
                "question": "Why does a foundation embedding model with top-tier Semantic Textual Similarity (STS) scores on MTEB often underperform on technical document retrieval?",
                "options": [
                    "STS measures symmetric paraphrase similarity between short sentences, whereas technical retrieval is asymmetric and demands hard-negative discrimination.",
                    "STS benchmarks evaluate models using lexical BM25 algorithms that ignore semantic vector weights.",
                    "MTEB leaderboards evaluate models strictly on image classification tasks rather than natural language text.",
                    "Technical retrieval datasets prohibit the use of cosine similarity and require Euclidean distance metrics."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "STS evaluates symmetric short-sentence equivalence, while enterprise document retrieval is inherently asymmetric, requiring models trained with hard negatives to discriminate subtle domain-specific technical facts."
            }
        },
        {
            "title": "Information Asymmetry & The Query-Document Discrepancy",
            "say": part4_say,
            "example": "A detective matching a three-word telegraphic description against a room full of detailed legal dossiers.",
            "code": code1,
            "output": output1,
            "tryIt": "Calculate Reciprocal Rank Fusion scores combining sparse lexical rankings with dense semantic rankings.",
            "check": {
                "question": "How does Reciprocal Rank Fusion (RRF) resolve the blind spots of dense Bi-Encoders when queries contain exact alphanumeric identifiers?",
                "options": [
                    "By merging candidate rankings from lexical BM25 search with dense vector rankings without requiring complex score normalization.",
                    "By retraining the transformer embedding model at query time using gradient descent.",
                    "By converting all alphanumeric strings into Roman numerals before computing cosine similarities.",
                    "By replacing vector databases with relational SQL databases for all semantic queries."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "RRF combines candidate rankings from BM25 (which catches exact alphanumeric IDs) and dense vector search (which catches conceptual synonyms), providing robust hybrid recall."
            }
        },
        {
            "title": "Cross-Encoder Re-Ranking & The Quadratic Computational Barrier",
            "say": part5_say,
            "example": "A supreme court justice meticulously examining evidence line-by-line during oral arguments rather than reading a summary card.",
            "code": code1,
            "output": output1,
            "tryIt": "Compare the computational complexity of Bi-Encoder ANN search against full Cross-Encoder multi-pass re-ranking.",
            "check": {
                "question": "What fundamental trade-off prevents Cross-Encoders from serving as first-stage retrieval engines over million-document corporate collections?",
                "options": [
                    "Cross-Encoders evaluate full pairwise cross-attention at runtime, making search across millions of documents computationally prohibitive.",
                    "Cross-Encoders cannot process documents longer than sixteen tokens due to transformer attention constraints.",
                    "Cross-Encoders produce lower retrieval accuracy than Bi-Encoders on all benchmark datasets.",
                    "Cross-Encoders require specialized quantum computers that are unavailable in commercial cloud datacenters."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Cross-Encoders evaluate full cross-attention over concatenated query-document sequences at runtime, requiring millions of forward passes per query and destroying interactive latency budgets."
            }
        }
    ],
    "summary": [
        "Dense Bi-Encoder architectures decouple query and document encoding into independent Siamese towers, enabling sub-millisecond approximate nearest neighbor search over millions of offline indexed vectors.",
        "Mean and CLS pooling operators impose an extreme 500x information compression bottleneck, collapsing hundreds of token vectors into a single coordinate and triggering vector smearing across multi-topic documents.",
        "The Massive Text Embedding Benchmark (MTEB) reveals that high performance on symmetric Semantic Textual Similarity does not translate into high accuracy on asymmetric technical document retrieval.",
        "Information asymmetry between short telegraphic user queries and dense technical documentation degrades cosine similarity matching, necessitating hybrid search fusion with BM25 via Reciprocal Rank Fusion (RRF).",
        "Cross-Encoders achieve maximum semantic accuracy through unrestricted token-level cross-attention, but their quadratic computational cost restricts them strictly to second-stage re-ranking over candidate pools.",
        "The fundamental tension between Bi-Encoder indexing efficiency and Cross-Encoder interactive precision motivates token-level late interaction architectures like ColBERT."
    ],
    "projectStep": {
        "title": "Enterprise Dense Bi-Encoder Information Bottleneck Diagnostic Suite",
        "steps": [
            "Construct a vector pooling compression simulator quantifying information loss across varying document lengths.",
            "Implement a hybrid Reciprocal Rank Fusion (RRF) ranker combining dense inner products with sparse BM25 scores.",
            "Benchmark candidate recall ceilings comparing single-stage Bi-Encoder retrieval against two-stage Cross-Encoder re-ranking."
        ]
    }
}

captions_data = [
    {
        "say1": "Bi encoder architectures decouple query and document encoding into towers.",
        "say2": "Decoupled encoding enables sub millisecond nearest neighbor search.",
        "example": "Library catalog cards summarize five hundred page volumes onto index cards.",
        "tryIt": "Evaluate vector pooling compression and inspect inner product similarity."
    },
    {
        "say1": "Vector pooling collapses hundreds of token vectors into coordinates.",
        "say2": "Vector smearing blends orthogonal topics and destroys entity bindings.",
        "example": "Blending distinct primary paint colors produces muddy brown composites.",
        "tryIt": "Compute compression ratios of collapsing token vectors into single vectors."
    },
    {
        "say1": "Massive text embedding benchmark evaluates models across diverse tasks.",
        "say2": "Symmetric sentence similarity does not guarantee asymmetric retrieval.",
        "example": "Decathlon athletes excel generally but lose to specialized sprinters.",
        "tryIt": "Analyze divergence between sentence similarity and retrieval accuracy."
    },
    {
        "say1": "Information asymmetry separates telegraphic queries from dense documents.",
        "say2": "Hybrid search pipelines fuse dense vectors with lexical keyword matching.",
        "example": "Detectives match brief telegraphic clues against dense legal dossiers.",
        "tryIt": "Calculate Rank Fusion scores combining sparse and dense rankings."
    },
    {
        "say1": "Cross encoders evaluate unrestricted full cross attention at every layer.",
        "say2": "Pairwise token interactions across layers resolve exact entity bindings.",
        "example": "Supreme court justices examine evidence line by line during oral arguments.",
        "tryIt": "Compare computational complexity of bi encoders against cross encoders."
    }
]

titles = [
    "Bi Encoder Siamese Architecture and Decoupled Processing Pipeline.",
    "Vector Pooling Information Bottleneck and Semantic Smearing Dynamics.",
    "Massive Text Embedding Benchmark Evaluation and Task Specialization.",
    "Information Asymmetry Dynamics and Hybrid Rank Fusion Architecture.",
    "Cross Encoder Full Attention Architecture and Computational Complexity."
]

columns_list = [
    ["Architecture Component", "Encoding Processing Mode", "Operational Latency Metric"],
    ["Pooling Operation", "Information Retained Ratio", "Semantic Smearing Risk"],
    ["Benchmark Category", "Evaluation Metric Standard", "Domain Transfer Robustness"],
    ["Retrieval Channel", "Scoring Mechanism Type", "Exact Keyword Fidelity"],
    ["Encoder Paradigm", "Cross Attention Coverage", "Million Document Query Cost"]
]

steps_rows = [
    [
        [["Query Tower Model", "Real Time Inference", "Twelve Milliseconds Subsecond"], ["Document Tower Model", "Offline Background Batch", "One Time Compute Ingestion"]],
        [["Shared Vector Space", "Seven Hundred Sixty Eight Floats", "L Two Normalized Coordinates"], ["ANN Vector Database", "Hierarchical Navigable Small World", "Five Millisecond Search"]],
        [["Library Catalog Index", "Three By Five Inch Card", "Compressed Volume Overview"], ["Full Stack Book Manuscript", "Three Hundred Printed Pages", "Exhaustive Knowledge Corpus"]],
        [["Cosine Similarity Dot Product", "Zero Point Nine Nine Two One Score", "Coarse Semantic Match"], ["Token Level Interaction", "Zero Runtime Token Awareness", "Decoupled Processing Limit"]]
    ],
    [
        [["Mean Vector Pooling", "Zero Point Two Percent Information", "Severe Topic Blending"], ["CLS Token Pooling", "Single Token Coordinate", "High Vulnerability To Drift"]],
        [["Contextual Hidden States", "Three Hundred Ninety Three Thousand Floats", "Zero Compression Degradation"], ["Pooled Output Vector", "Seven Hundred Sixty Eight Floats", "Five Hundred Fold Loss"]],
        [["Primary Paint Palette", "Pure Distinct Color Pigments", "Sharp Visual Definition"], ["Blended Paint Mixture", "Uniform Muddy Composite", "Irreversible Pigment Loss"]],
        [["Entity Relation Bindings", "Decoupled Attribute Pairs", "High False Positive Risk"], ["Isolated Keyword Search", "Zero Contextual Awareness", "Brittle Keyword Dependence"]]
    ],
    [
        [["Semantic Textual Similarity", "Spearman Correlation Rank", "High Symmetric Fragility"], ["Information Retrieval BEIR", "Normalized Discounted Gain", "Severe Out Of Domain Drop"]],
        [["Hard Negative Mining", "BM Twenty Five Filtered Negatives", "Robust Boundary Discrimination"], ["Random In Batch Negatives", "Coarse Topic Separation", "Zero Fine Grained Fidelity"]],
        [["Decathlon Multi Sport", "Balanced Moderate Mastery", "Average Universal Ranking"], ["Specialized Hundred Meter Sprint", "Peak Velocity Acceleration", "Domain Specific Dominance"]],
        [["Matryoshka Truncation", "Two Hundred Fifty Six Dimensions", "Ninety Six Percent Accuracy"], ["Full Dimension Vector", "One Thousand Five Hundred Dimensions", "Six Fold Higher RAM"]]
    ],
    [
        [["Telegraphic User Query", "Five Token Average Length", "High Semantic Underspecification"], ["Corporate Technical Document", "Five Hundred Token Length", "Dense Structured Specifications"]],
        [["Dense Neural Channel", "Dense Cosine Similarity", "Zero Exact Alphanumeric Precision"], ["Lexical BM Twenty Five Channel", "Inverse Document Frequency", "One Hundred Percent Exact Match"]],
        [["Investigator Cablegram", "Three Word Coded Message", "Sparse Clue Indication"], ["Government Dossier Archive", "Multi Volume Filing Cabinets", "Exhaustive Case Records"]],
        [["Reciprocal Rank Fusion", "Reciprocal Rank Summation", "Fifteen Percent MRR Lift"], ["Isolated Vector Query", "Single Candidate Ranking", "Frequent Alphanumeric Failure"]]
    ],
    [
        [["Siamese Bi Encoder", "Zero Runtime Cross Attention", "Sub Ten Millisecond Search"], ["Unified Cross Encoder", "Full Pairwise Cross Attention", "Ten Minute Multi Pass Scan"]],
        [["Two Stage Re Ranking", "Top One Hundred Candidates", "Fifty Millisecond End To End"], ["First Stage Candidate Recall", "Recall Bottleneck Risk", "Permanent Document Loss"]],
        [["Supreme Court Justice", "Meticulous Evidence Audit", "Flawless Judgment Precision"], ["Preliminary Bailiff Screen", "High Speed Document Triage", "Coarse Candidate Filtering"]],
        [["Late Interaction Frontier", "Token Level MaxSim Operator", "Best Of Both Worlds Capability"], ["Production Serving Ready", "Sub Millisecond Low Latency", "Enterprise Grade Precision"]]
    ]
]

entries = []
for p_idx, part in enumerate(day41_dict['parts']):
    code_hash = hashlib.sha256(part['code'].encode('utf-8')).hexdigest()
    caps = captions_data[p_idx]
    
    spec_steps = []
    at_keys = ["say1", "say2", "example", "tryIt"]
    for s_idx, at_k in enumerate(at_keys):
        cap = caps[at_k]
        assert len(cap) <= 75, f"Part {p_idx+1} {at_k} caption too long: {len(cap)} ({cap})"
        assert cap.endswith('.'), f"Part {p_idx+1} {at_k} caption must end with period: ({cap})"
        assert not any(c.isdigit() for c in cap), f"Part {p_idx+1} {at_k} caption contains digits: ({cap})"
        spec_steps.append({
            "at": at_k,
            "caption": cap,
            "rows": steps_rows[p_idx][s_idx]
        })
        
    spec = {
        "template": "table",
        "title": titles[p_idx],
        "columns": columns_list[p_idx],
        "steps": spec_steps
    }
    assert len(spec["title"]) <= 75, f"Part {p_idx+1} title too long: {len(spec['title'])}"
    assert spec["title"].endswith('.'), f"Part {p_idx+1} title must end with period"
    assert not any(c.isdigit() for c in spec["title"]), f"Part {p_idx+1} title contains digits"
    
    entries.append({
        "partTitle": part["title"],
        "codeHash": code_hash,
        "spec": spec,
        "filled": spec
    })

visual_envelope = {
    "schemaVersion": "2.0.0",
    "prefix": "ai",
    "day": 41,
    "entries": entries
}

# Write lesson JSON
with open("scripts/branch_c/day41_lesson.json", "w", encoding="utf-8") as f:
    json.dump(day41_dict, f, indent=2)

# Write visual envelope
with open("src/lib/data/lessonVisuals/ai/day-41.json", "w", encoding="utf-8") as f:
    json.dump(visual_envelope, f, indent=2)

print(f"Generated Day 41 lesson JSON ({total_words} words) and Visual Envelope successfully!")
