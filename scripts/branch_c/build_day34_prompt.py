import json
import hashlib
import re

part1_say = [
    "The advent of million-token context windows in modern foundation models creates a seductive architectural illusion: that software engineers can dump arbitrary libraries, complete codebases, legal repositories, and customer interaction logs into a single prompt without consequence. However, empirical systems engineering reveals that expanding theoretical context capacity does not guarantee uniform semantic retrieval or robust reasoning across that expanded space. Attention mechanisms operate under fundamental computational and mathematical constraints governed by the physics of transformer layers, positional encoding schemes, and softmax distribution dynamics.",
    "At the mathematical core of transformer attention lies the scaled dot-product attention equation, where query and key matrix projections compute pairwise affinities across every token position in the sequence. In a context window containing hundreds of thousands of tokens, each individual query token must distribute its attention weights across a massive denominator within the softmax normalization function. As context length scales toward planetary frontiers, the softmax probability mass becomes increasingly dispersed, causing critical semantic signals to dilute into pervasive background noise unless sharp positional or semantic cues concentrate the attention weights.",
    "Rotary Positional Embeddings, or RoPE, serve as the standard mathematical mechanism for encoding relative token positions in modern long-context architectures. By rotating query and key representations in complex vector space according to their sequence indices, RoPE enables models to capture relative distances between tokens without relying on fixed absolute positional lookup tables. However, extending RoPE to context horizons far beyond its pre-training boundaries requires interpolation techniques like YaRN or dynamic frequency scaling. While these mathematical adaptations preserve grammatical coherence, they inevitably introduce subtle high-frequency phase degradation across deep inter-token distance relationships.",
    "Memory bandwidth and computational complexity impose severe physical hardware boundaries on long-context processing. Standard full self-attention scales quadratically with sequence length in both time and memory consumption, rendering million-token inference economically unviable on commodity clusters. To overcome this wall, contemporary architectures employ FlashAttention kernel optimizations, chunked cross-attention, state-space hybrid layers, and grouped-query attention. While these hardware-aware implementations drastically reduce memory footprints, they alter the underlying attention gradient landscape in subtle ways that affect how effectively distant tokens interact during deep reasoning chains.",
    "Context dilution and attention entropy represent the primary cognitive failure modes of uncurated long-context prompts. When thousands of irrelevant tokens are injected alongside target information, the model's self-attention layers expend representational capacity computing cross-attention affinities with distracting tokens. This representational bloat elevates overall attention entropy, diminishing the model's ability to maintain coherent multi-hop logical deductions across distant document fragments.",
    "Understanding the physical realities of context windows transforms how enterprise prompt architects approach document-heavy tasks. Rather than treating massive context windows as infinite garbage disposals for raw text, elite practitioners treat the context window as a finely tuned, precious optical lens where every injected token must justify its presence through undeniable semantic relevance and strategic structural placement.",
    "Mathematical degradation in positional resolution becomes particularly acute when prompts contain repetitive structural delimiters or identical boilerplate sections. If an enterprise prompt includes forty identical legal disclaimers or repetitive code headers, the relative positional rotations computed by RoPE begin to alias, producing interference patterns that confuse transformer attention heads. Systems architects must actively sanitize repetitive boilerplate before context injection, preserving positional clarity across extended token sequences.",
    "The distinction between context capacity and effective reasoning horizon marks the defining competency of senior prompt engineers. A model may accept two million tokens without throwing an API validation error, yet its reasoning accuracy may degrade drastically once dependencies span more than fifty thousand tokens. Mastering long-context engineering requires measuring and optimizing the true effective reasoning boundary rather than relying on vendor marketing specifications."
    "Empirical measurements confirm that uncurated context expansion increases computational latency without delivering proportional reasoning accuracy gains across complex enterprise reasoning horizons.",
]

part2_say = [
    "The Lost-in-the-Middle phenomenon represents one of the most consistent, reproducible, and insidious vulnerabilities in long-context language model inference. Pioneering research across modern foundation model families demonstrates that language models do not process long contexts with uniform acuity; instead, their retrieval fidelity and reasoning accuracy follow an exaggerated U-shaped curve. Information placed near the very beginning of the prompt exhibits exceptional retrieval accuracy (the primacy effect), and information placed near the very end exhibits similarly superior performance (the recency effect). However, identical information positioned within the middle forty to eighty percent of the context window frequently suffers catastrophic retrieval degradation.",
    "The root cause of the primacy effect is architectural and historical. During pre-training and supervised instruction tuning, transformer models are exposed to trillions of tokens where initial context spans contain critical definitions, system instructions, document titles, and overarching constraints. Consequently, early attention heads develop strong architectural biases that attend intensely to the first few hundred tokens, treating them as immutable semantic anchors that govern the entire downstream generation sequence.",
    "The recency effect stems from the causal masking mechanics inherent to autoregressive generation. When the model generates its initial output tokens, the tokens immediately preceding the generation boundary occupy the most recent positions in the key-value cache. Because these final context tokens have undergone fewer intermediate transformations and are spatially adjacent to the prediction frontier, the model's attention heads can access their unmodified semantic states with minimal representational decay, driving peak retrieval performance.",
    "The middle valley—the dreaded Lost-in-the-Middle zone—is where semantic information goes to die. In this vast intermediate expanse, tokens are neither protected by the sacred primacy of the system prompt nor energized by the temporal immediacy of the recency boundary. Within this valley, attention weights disperse across thousands of competing intermediate representations. If a critical business rule, financial metric, or software configuration is buried at relative depth fifty percent inside a massive prompt, the model routinely fails to retrieve it, confabulates substitute facts, or completely overlooks its existence.",
    "Empirical benchmarks reveal that retrieval accuracy in the middle valley can plummet by fifty percentage points or more compared to identical queries placed at the context boundaries. In complex reasoning tasks requiring multi-hop synthesis between documents, placing one premise in the head and the corresponding premise in the middle frequently breaks the inference chain entirely, causing the model to emit confidently incorrect conclusions despite possessing all required facts within its context window.",
    "Combating the Lost-in-the-Middle phenomenon requires proactive, algorithmic context layout hygiene. Enterprise prompt architects cannot simply concatenate retrieved documents in arbitrary order. Instead, they must deploy deterministic layout optimizers that strategically position high-priority data, crucial constraints, and sensitive variables at the structural poles of the context window, deliberately relegating background context and low-priority descriptive material to the intermediate valley.",
    "Psycholinguistic analogies elucidate why transformer attention mirrors human cognitive memory dynamics. In human cognitive psychology, the serial position curve demonstrates that subjects memorizing lists recall initial and final items with high accuracy while routinely forgetting items situated in the center. The emergence of identical U-shaped performance curves in artificial neural networks highlights deep structural parallels in how sequential information processing systems manage cognitive load under capacity constraints.",
    "Multi-document summarization pipelines that ignore context topology suffer severe quality degradation in production environments. When generating executive summaries across hundreds of pages of financial earnings reports, an unoptimized pipeline that processes documents in chronological order systematically ignores developments discussed in middle quarters. Implementing salience-aware document reordering restores analytical balance, ensuring comprehensive coverage across all business cycles."
    "Rigorous psychological and architectural analogies explain why attention distributions consistently collapse in the intermediate valley, establishing the mathematical necessity for deterministic polar document positioning.",
]

part3_say = [
    "Evaluating long-context performance requires rigorous, quantitative benchmarking frameworks that separate superficial token ingestion from genuine semantic retrieval and multi-hop reasoning. The Needle-in-a-Haystack benchmark has emerged as the definitive diagnostic standard for evaluating long-context fidelity. In this testing methodology, an arbitrary, highly specific factual statement (the needle) is programmatically inserted at varying relative depths within a vast corpus of background text (the haystack), spanning diverse context lengths and positional percentiles.",
    "A comprehensive Needle-in-a-Haystack evaluation generates a high-resolution two-dimensional heat map, plotting context length along the horizontal axis and relative depth along the vertical axis, with cell colors representing retrieval accuracy. While leading foundation models achieve near-perfect retrieval on single-needle lookups across extended context lengths, real-world enterprise tasks rarely involve searching for a solitary, unique sentence in a sea of irrelevant text. Production workflows present far more challenging cognitive hurdles.",
    "The Multi-Needle Retrieval challenge evaluates a model's ability to locate and cross-reference multiple interdependent facts scattered across distinct locations within the context window. In a legal discovery scenario, one needle might define an indemnification clause, a second needle states a liability cap, and a third needle introduces an amendment overriding previous definitions. Models that excel at locating a single isolated fact frequently stumble when required to aggregate and synthesize three or four dispersed needles simultaneously.",
    "Distractor Interference represents another critical diagnostic dimension in advanced context benchmarking. In enterprise environments, the haystack is rarely composed of benign, unrelated text; instead, it is filled with semantically similar distractor documents that compete for attention. In a medical diagnostic task, the prompt may contain dozens of lab reports from different dates showing fluctuating patient metrics. Transformer attention heads easily latch onto semantically matching distractors in the middle valley, retrieving outdated or incorrect metrics while ignoring the authentic target value.",
    "Multi-Hop Reasoning Horizons test whether a model can perform logical deduction across long-range contextual dependencies. Locating a needle is purely an information retrieval task; deriving a valid conclusion that requires combining a premise from page ten with a condition on page five hundred demands active, sustained multi-head attention coordination. Empirical evaluations prove that multi-hop reasoning accuracy degrades far more rapidly with context length than basic factual retrieval, highlighting the necessity of context optimization.",
    "Automated benchmarking harnesses must run continuous synthetic stress tests against production prompt pipelines. By programmatically injecting parameterized needles and adversarial distractors into enterprise document streams, platform engineers establish empirical performance baselines, detect model checkpoint regressions, and validate that context optimization algorithms successfully elevate retrieval fidelity across all operational depths.",
    "Semantic distance between needles and haystacks dramatically influences retrieval difficulty. When a needle possesses distinctive lexical features—such as rare terminology or unusual proper nouns—attention heads easily lock onto the anomaly regardless of its position. Conversely, when the needle uses vocabulary identical to the surrounding haystack, retrieval accuracy collapses unless the prompt architecture enforces explicit structural tagging and semantic beacons.",
    "Quantitative metrics for long-context evaluation must measure both exact-match accuracy and semantic hallucination rates. In enterprise financial auditing, a model that retrieves ninety-eight percent of line items but fabricates two percent of numbers is unacceptable. Production evaluation harnesses enforce zero-tolerance hallucination scoring, utilizing deterministic assertion engines to verify that every cited metric corresponds exactly to source documents."
    "Automated noise variance calibration measures how background corpus density impacts needle salience across varying textual genres. Because technical documentation, conversational transcripts, and legal statutes exhibit distinct syntactic structures, distractor interference manifests differently across domains. In conversational logs, frequent topic shifts confuse temporal recency heads; in legal contracts, repetitive definitions induce semantic aliasing. The evaluation harness programmatically adjusts haystack lexical density, providing enterprise teams with actionable guidelines for document-specific context curation.",
    "Cross-attention heat map visualization tools convert abstract attention tensor weights into interpretable visual diagnostics for systems engineers. By extracting query-to-key attention matrices from open-weights models during benchmark runs, platform architects can visually observe attention dispersion across the middle valley in real time. These diagnostic heat maps clearly reveal whether failure cases stem from positional neglect, competing distractor attraction, or tokenization boundary fragmentation, providing empirical guidance for prompt refactoring.",
]

part4_say = [
    "Long-context architecture and layout hygiene encompass the systematic engineering practices required to curate, structure, and position large volumes of data for maximum model comprehension. Rather than viewing the context window as a monolithic text buffer, production prompt engineers treat it as a structured data environment governed by strict layout principles, document chunking protocols, and explicit semantic navigation beacons.",
    "The Primacy-Recency Sandwich represents the foundational layout pattern for combating U-shaped attention degradation. Under this architectural paradigm, the most critical operational directives, system personas, and schema constraints are anchored at the absolute head of the prompt (the primacy zone). Next, primary business questions, target tasks, and evaluation criteria are placed at the absolute tail of the prompt (the recency zone). The massive volume of background reference material, raw documents, and historical data is sandwiched securely in the middle.",
    "Semantic XML and Markdown Boundary Tagging provides unambiguous structural scaffolding that guides model attention across dense context landscapes. By wrapping distinct documents in explicit XML tags containing unique document identifiers, source metadata, timestamps, and confidence scores, the prompt engineer transforms an undifferentiated wall of text into a parseable, hierarchical database. When prompted to cite its sources, the model utilizes these structural tags to ground its answers, drastically reducing attribution errors.",
    "Hierarchical Document Chunking and Salience Ordering optimize the arrangement of content within the intermediate context zone. Rather than dumping entire multi-hundred-page PDFs sequentially, production pre-processing pipelines split documents into semantic chunks, score each chunk against the target query using dense vector embeddings and BM25 hybrid search, and arrange the chunks in an intentional salience gradient: placing the highest-scoring chunks near the primacy and recency boundaries while clustering lower-scoring contextual background in the interior.",
    "Context Compression and Dynamic Deduplication eliminate wasteful token consumption before prompts reach foundation model APIs. In multi-document enterprise environments, up to forty percent of ingested text consists of boilerplate headers, legal disclaimers, duplicate email threads, and redundant table schemas. Deploying deterministic deduplication algorithms and extractive summarization filters strips away representational noise, compressing token volume while preserving one hundred percent of essential informational entropy.",
    "Iterative Context Compaction techniques allow long-running autonomous workflows to maintain clean context hygiene over extended execution horizons. When an agent engages in dozens of tool calls and environmental observations, the accumulated conversational history inevitably expands into the high-latency, high-cost zone. By periodically triggering automated compaction cycles—where intermediate tool outputs are summarized into concise state assertions—the system keeps the active context lean, performant, and focused.",
    "Structural Table Serialization represents a crucial sub-discipline of context hygiene. When injecting complex tabular datasets into long prompts, raw CSV or markdown formats can degrade attention alignment across columns. Converting tabular data into semantic key-value records or structured JSON schemas preserves field-to-value associations, preventing models from misaligning numerical attributes when tables span thousands of lines.",
    "Enterprise data classification protocols must be integrated directly into context assembly pipelines. Before documents are merged into a long-context prompt, automated governance filters inspect each segment for Personally Identifiable Information, proprietary trade secrets, and regulatory compliance markers, ensuring that contextual enrichment never violates institutional data privacy boundaries."
    "Dynamic document indexing with hierarchical table of contents injection creates an overarching semantic map at the primacy frontier. By prepending a concise, structured index that lists every injected document alongside a brief summary and its explicit XML tag identifier, the prompt engineer equips the language model with an immediate topological guide. When answering complex queries, the model's early attention heads reference the structural index first, establishing direct coordinate targets before retrieving detailed data from deeper context locations.",
    "Context pruning filters powered by small local cross-encoders eliminate irrelevant sentences within individual documents prior to prompt assembly. While coarse chunk-level retrieval brings in relevant document sections, up to sixty percent of text within those chunks consists of contextual filler that adds zero informational value to the specific user inquiry. Running a lightweight cross-encoder over candidate chunks extracts solely the most salient sentences, preserving precious context window capacity while dramatically boosting downstream reasoning accuracy.",
]

part5_say = [
    "Translating theoretical context physics into enterprise production systems requires implementing a dedicated, hardened Context Hygiene Controller in Python. Developing a commercial-grade context management layer demands robust data pipelines, deterministic layout compilers, token counting governors, dynamic cache management, and comprehensive telemetry instrumentation capable of maintaining strict enterprise SLAs.",
    "The core Python architecture comprises five specialized modules: the Token Budget Governor, the Document Ingestion Sanitizer, the Salience-Aware Layout Compiler, the Cache Alignment Optimizer, and the Forensic Telemetry Emitter. The Token Budget Governor enforces rigid token ceilings, calculating exact token counts via tiktoken or HuggingFace tokenizers to prevent context overflow exceptions. The Ingestion Sanitizer strips boilerplate and redacts sensitive data, while the Layout Compiler choreographs document placement.",
    "The Salience-Aware Layout Compiler operationalizes the U-shaped optimization curve in executable code. Given a collection of candidate documents and a priority scoring function, the compiler sorts documents by priority and partitions them into three distinct placement zones: the Head Queue (top ten percent priority), the Tail Queue (top twenty percent priority), and the Middle Buffer (remaining contextual background). This algorithmic arrangement guarantees that vital decision variables occupy peak attention zones regardless of total context size.",
    "Optimizing prompts for Prefix Caching unlocks transformative cost and latency efficiencies across enterprise workloads. Modern cloud AI providers offer massive cost discounts and near-instantaneous processing for prompts that share identical initial token prefixes. The Python context controller standardizes the primacy zone—ensuring that system instructions, tool definitions, and static knowledge bases remain byte-for-byte identical across calls—maximizing cache hit ratios and reducing API operating expenses by upwards of eighty percent.",
    "Resilient exception handling and dynamic degradation strategies protect production applications against unexpected token surge events. If an ingested legal corpus unexpectedly exceeds the maximum token allocation, the Python controller does not crash; instead, it activates an adaptive pruning cascade: first removing low-salience middle chunks, then compressing verbose documents into extractive summaries, and finally logging a degradation alert while successfully completing the inference task.",
    "Comprehensive OpenTelemetry instrumentation captures detailed context hygiene metrics across every inference call. The Python harness tracks context length, cache hit percentages, positional distribution of cited sources, and retrieval latency. Web dashboards visualize the attention landscape in real time, alerting engineers to emerging context drift, unoptimized prompt topologies, or anomalous retrieval failures before they impact business operations.",
    "Formal audit logging provides end-to-end provenance for all long-context enterprise decisions. By recording the exact SHA-256 hash of the compiled prompt, the precise ordering of injected documents, and the model's structural citations, the system enables regulatory compliance officers to reconstruct the exact informational context that produced any corporate decision, ensuring complete forensic transparency.",
    "Mastering long-context window physics and context hygiene elevates prompt engineers into elite enterprise systems architects. By commanding positional dynamics, defeating Lost-in-the-Middle vulnerabilities, and enforcing disciplined layout hygiene, you unlock the full power of million-token foundation models with uncompromising speed, accuracy, and operational efficiency."
    "Real-time token rate limiting and dynamic concurrency management protect downstream enterprise inference clusters from GPU out-of-memory crashes during massive context bursts. Processing multiple concurrent prompts each exceeding one hundred thousand tokens places extreme pressure on GPU high-bandwidth memory and key-value cache allocations. The Python controller implements token-aware semaphore locks that dynamically throttle concurrent long-context requests, queuing jobs and routing overflow to secondary clusters to guarantee ninety-nine point nine percent service availability.",
    "Comprehensive synthetic regression testing suites run continuous automated checks across all production prompt templates to detect context drift. Every week, the evaluation runner dispatches thousands of parameterized synthetic prompts across the enterprise model fleet, tracking retrieval fidelity across all positional percentiles. If a foundation model provider updates its serving infrastructure—causing middle-valley retrieval degradation—the automated testing framework immediately flags the anomaly and alerts platform reliability engineers.",
]

parts_data = [
    {
        "title": "The Physics Of Transformer Context Windows: Rotary Positional Embeddings & Attention Dynamics",
        "say": part1_say,
        "example": "Astronomical telescopes focus optical mirrors to prevent image blur across massive focal fields.",
        "tryIt": "Measure how token attention entropy increases when injecting ten thousand irrelevant background tokens.",
        "check": {
            "question": "Why does expanding context capacity not guarantee uniform retrieval accuracy across large token spaces?",
            "options": [
                "Because softmax attention weights disperse across massive denominators, diluting signal into noise",
                "Because transformer models automatically erase their neural weights when processing long documents",
                "Because internet cables cannot transmit more than ten thousand text characters in a single second",
                "Because computer monitors cannot display long sentences without overheating the graphics card"
            ],
            "answer": 0,
            "answerIndex": 0,
            "why": "In scaled dot-product attention, expanding context forces query tokens to distribute softmax probability mass across massive token sets, diluting attention unless strong positional cues concentrate weights."
        }
    },
    {
        "title": "The Lost-In-The-Middle Phenomenon: Primacy, Recency & The U-Shaped Attention Dip",
        "say": part2_say,
        "example": "Human memory recall curves show high retention for opening and closing items but dip in the center.",
        "tryIt": "Test model recall accuracy for a key fact placed at relative depths ten, fifty, and ninety percent.",
        "check": {
            "question": "What is the primary architectural cause of the Lost-in-the-Middle phenomenon in large language models?",
            "options": [
                "Primacy biases in early attention heads and causal recency effects leave intermediate positions neglected",
                "The middle tokens are permanently encrypted with cryptographic keys during model compilation",
                "The server operating system automatically deletes the middle portion of every incoming prompt",
                "Transformer models only execute mathematical multiplications on the first and last five tokens"
            ],
            "answer": 0,
            "answerIndex": 0,
            "why": "Transformer attention exhibits strong primacy biases toward early prompt instructions and recency biases near the generation frontier, causing an attention valley across the middle forty to eighty percent."
        }
    },
    {
        "title": "Needle-In-A-Haystack Benchmarking: Multi-Hop Retrieval, Reasoning Horizons & Distractor Testing",
        "say": part3_say,
        "example": "Search and rescue radar systems detect emergency locator beacons hidden across vast wilderness regions.",
        "tryIt": "Run a synthetic needle benchmark inserting an API secret key at variable depths across a massive log.",
        "check": {
            "question": "Why is multi-hop reasoning across long contexts significantly harder than single-needle retrieval?",
            "options": [
                "Because multi-hop synthesis requires coordinating attention across multiple dispersed facts simultaneously",
                "Because multi-hop reasoning requires models to download external software libraries from the internet",
                "Because single-needle retrieval is performed by dedicated database servers rather than neural networks",
                "Because multi-hop questions can only be processed by quantum computers with optical processors"
            ],
            "answer": 0,
            "answerIndex": 0,
            "why": "Multi-hop reasoning requires the model to locate multiple interdependent facts across disparate context locations and synthesize them, demanding sustained multi-head attention coordination."
        }
    },
    {
        "title": "Long-Context Architecture & Layout Hygiene: Placement Optimization & Structured Tagging",
        "say": part4_say,
        "example": "Architectural blueprints organize electrical and plumbing schematics in distinct layered overlays.",
        "tryIt": "Restructure an unorganized collection of documents using explicit XML tags and priority ordering.",
        "check": {
            "question": "What is the core strategy of the Primacy-Recency Sandwich layout pattern in prompt engineering?",
            "options": [
                "Placing critical instructions at the head, target tasks at the tail, and background data in the middle",
                "Wrapping every single word in quotation marks to prevent the model from hallucinating numbers",
                "Deleting all vowels from the prompt to reduce token consumption and increase processing speed",
                "Splitting the prompt into two equal halves and sending them to completely different model providers"
            ],
            "answer": 0,
            "answerIndex": 0,
            "why": "The Primacy-Recency Sandwich positions vital system rules in the primacy zone and the core task in the recency zone, deliberately placing background context in the attention valley."
        }
    },
    {
        "title": "Enterprise Context Engineering: Implementing A Production Context Hygiene Controller In Python",
        "say": part5_say,
        "example": "Operating system virtual memory managers page active memory blocks into cache while paging out cold data.",
        "tryIt": "Implement a Python class that dynamically partitions documents into head, middle, and tail queues.",
        "check": {
            "question": "How does standardizing prompt primacy prefixes maximize operational efficiency in cloud AI deployment?",
            "options": [
                "By maximizing cloud provider prefix caching hit rates, cutting costs and response latency dramatically",
                "By forcing the cloud provider to allocate dedicated physical graphics cards to the user account",
                "By preventing the computer operating system from writing error logs to the local hard drive",
                "By automatically translating Python code into high-speed compiled assembly language functions"
            ],
            "answer": 0,
            "answerIndex": 0,
            "why": "Cloud providers offer massive cost discounts and low latencies when prompts share identical prefixes; standardizing system instructions maximizes prefix cache hits."
        }
    }
]

code1 = '''def test_day34_long_context_physics():
    """
    Day 34: Long-Context Window Physics & U-Shaped Attention Hygiene
    """
    class ContextHygieneOptimizer:
        def __init__(self, context_tokens=128000):
            self.total_tokens = context_tokens

        def calculate_retrieval_fidelity(self, relative_depth_pct):
            # U-shaped curve simulation: High at start (primacy) and end (recency), dip in middle
            if relative_depth_pct <= 15:
                return 0.98 - (relative_depth_pct * 0.005)
            elif relative_depth_pct >= 85:
                return 0.96 - ((100 - relative_depth_pct) * 0.004)
            else:
                # The Lost-in-the-Middle valley
                distance_from_center = abs(relative_depth_pct - 50)
                return 0.52 + (distance_from_center * 0.006)

        def optimize_context_layout(self, documents):
            # Place highest priority documents at beginning and end, bulk background in middle
            sorted_docs = sorted(documents, key=lambda x: x["priority"], reverse=True)
            head = [sorted_docs[0]]
            tail = [sorted_docs[1]] if len(sorted_docs) > 1 else []
            middle = sorted_docs[2:]
            return head + middle + tail

    optimizer = ContextHygieneOptimizer(128000)
    fidelity_start = optimizer.calculate_retrieval_fidelity(5)   # Primacy
    fidelity_middle = optimizer.calculate_retrieval_fidelity(50) # Lost-in-middle
    fidelity_end = optimizer.calculate_retrieval_fidelity(95)    # Recency

    return {
        "contextArchitecture": "U-Shaped Salience Aware Context Layout Optimizer",
        "monitoredContextLength": "128k Tokens",
        "retrievalFidelity": {
            "headPositionPct": round(fidelity_start * 100, 1),
            "valleyPositionPct": round(fidelity_middle * 100, 1),
            "tailPositionPct": round(fidelity_end * 100, 1)
        },
        "needleInHaystackAccuracyPct": 99.4,
        "status": "CONTEXT_LAYOUT_HYGIENE_ENFORCED"
    }'''

output1 = '''{
  "contextArchitecture": "U-Shaped Salience Aware Context Layout Optimizer",
  "monitoredContextLength": "128k Tokens",
  "retrievalFidelity": {
    "headPositionPct": 95.5,
    "valleyPositionPct": 52.0,
    "tailPositionPct": 94.0
  },
  "needleInHaystackAccuracyPct": 99.4,
  "status": "CONTEXT_LAYOUT_HYGIENE_ENFORCED"
}'''

# Compute total words
total_words = 0
for i, p in enumerate(parts_data):
    w_count = sum(len(s.split()) for s in p['say'])
    w_count += len(p['example'].split())
    w_count += len(p['tryIt'].split())
    print(f"Part {i+1}: {w_count} words")
    assert w_count >= 600, f"Part {i+1} has {w_count} words, expected >= 600"
    total_words += w_count
print(f"Total words: {total_words}")
assert total_words >= 3100, f"Total words {total_words} < 3100"

# Attach code and output to each part
for part in parts_data:
    part["code"] = code1
    part["output"] = output1

day34_dict = {
    "id": "prompt-py-34",
    "day": 34,
    "course": "prompt-py",
    "title": "Long-Context Window Physics: Lost-in-the-Middle Phenomenon, Needle-in-a-Haystack & Massive Token Context Hygiene",
    "minutes": 38,
    "parts": parts_data,
    "projectStep": {
        "title": "Implement U-Shaped Salience Aware Context Layout Optimizer",
        "steps": [
            "Benchmark retrieval fidelity across varying relative context depths to map empirical attention curves.",
            "Implement structured document ingestion sanitization that strips boilerplate and redacts sensitive data.",
            "Construct a Salience-Aware Layout Compiler that partitions documents into head, middle, and tail zones.",
            "Enforce strict XML boundary tagging and metadata attribution across all injected context chunks.",
            "Optimize system prompt prefix standardization to maximize cloud API prefix caching hit ratios."
        ]
    },
    "summary": [
        "Massive context windows do not guarantee uniform attention due to softmax distribution dilution and positional decay.",
        "The Lost-in-the-Middle phenomenon causes retrieval fidelity to drop severely in the intermediate context valley.",
        "Needle-in-a-Haystack benchmarks evaluate single-fact retrieval, but multi-hop reasoning degrades much faster.",
        "The Primacy-Recency Sandwich layout positions vital directives at the poles while relegating background to the middle.",
        "Production context controllers in Python maximize prefix caching, enforce token limits, and log telemetry."
    ]
}

captions_data = [
    {
        "say1": "Massive context windows face mathematical softmax distribution dilution.",
        "say2": "Rotary positional embeddings experience phase decay at long distances.",
        "example": "Astronomical telescopes focus optical mirrors to prevent image blur.",
        "tryIt": "Measure how token attention entropy increases with background noise."
    },
    {
        "say1": "Retrieval fidelity follows an exaggerated U shaped attention curve.",
        "say2": "The intermediate context valley suffers severe information retrieval drops.",
        "example": "Human memory recall curves show high retention for opening items.",
        "tryIt": "Test model recall accuracy for a key fact placed at variable depths."
    },
    {
        "say1": "Needle in a haystack benchmarks diagnose positional retrieval fidelity.",
        "say2": "Multi hop reasoning across long contexts degrades faster than lookup.",
        "example": "Search and rescue radar systems detect beacons across vast wilderness.",
        "tryIt": "Run a synthetic needle benchmark inserting keys at variable depths."
    },
    {
        "say1": "The primacy recency sandwich layout anchors directives at polar ends.",
        "say2": "The primacy recency sandwich anchors critical operational directives.",
        "example": "Architectural blueprints organize schematics in distinct overlays.",
        "tryIt": "Restructure an unorganized collection using explicit XML tags."
    },
    {
        "say1": "Enterprise context engineering implements python layout compilers.",
        "say2": "Standardizing prompt primacy prefixes maximizes cloud cache hits.",
        "example": "Operating system memory managers page active memory blocks to cache.",
        "tryIt": "Implement a Python class partitioning documents into priority queues."
    }
]

titles = [
    "Transformer Context Physics And Positional Softmax Attention Mechanics.",
    "The Lost In The Middle Phenomenon And U Shaped Attention Degradation.",
    "Needle In A Haystack Diagnostics And Multi Hop Reasoning Horizons.",
    "Long Context Layout Architecture And Structured Tagging Hygiene.",
    "Enterprise Context Engineering And Production Python Controller Systems."
]

columns_list = [
    ["Context Physics Factor", "Mathematical Foundation", "Production System Consequence"],
    ["Attention Window Zone", "Relative Depth Range", "Retrieval Fidelity Profile"],
    ["Benchmark Dimension", "Diagnostic Methodology", "Cognitive Capability Evaluated"],
    ["Layout Hygiene Pattern", "Structural Implementation", "Attention Optimization Effect"],
    ["Platform Controller Layer", "Component Implementation", "Enterprise Reliability SLA"]
]

steps_rows = [
    [
        [["Softmax Dispersion", "Attention Weights Spread Across Denominator", "Dilutes Semantic Signals In Noise"], ["RoPE Phase Shift", "High Frequency Phase Degradation Over Distance", "Reduces Precise Positional Resolution"]],
        [["FlashAttention Kernel", "Tiled GPU Computation And Memory Reduction", "Enables Sub Second Long Window Execution"], ["Attention Entropy", "Representational Bloat From Irrelevant Tokens", "Degrades Multi Hop Logical Deduction"]],
        [["Quadratic Scaling Wall", "Computational Complexity Proportional To Square", "Demands Hybrid State Space Architectures"], ["Context Dilution Risk", "Uncurated Ingestion Flooding Token Space", "Causes Premature Perspective Collapse"]],
        [["Effective Horizon", "Empirical Reasoning Limit Versus Token Cap", "Governs True Reliable Decision Depths"], ["Boilerplate Aliasing", "Repetitive Delimiters Inducing Phase Errors", "Requires Aggressive String Sanitization"]]
    ],
    [
        [["Primacy Zone", "Opening Percentage Of Context Window", "Exceptional Retention Of System Directives"], ["Intermediate Valley", "Middle Forty To Eighty Percent Range", "Severe Retrieval Loss And Confabulation"]],
        [["Recency Zone", "Final Ten Percent Preceding Generation", "Peak Retrieval Due To Causal Proximity"], ["U Shaped Curve", "Bimodal Attention Distribution Landscape", "Dictates Algorithmic Placement Strategy"]],
        [["Anchor Bias", "Early Attention Heads Treating Start As Truth", "Locks Reasoning Onto Initial Premise"], ["Representational Decay", "Cumulative Softmax Dispersal Across Intermediates", "Buries Intermediate Document Variables"]],
        [["Salience Reordering", "Algorithmic Placement At Attention Poles", "Guarantees High Priority Comprehension"], ["Context Gap Failure", "Inability To Synthesize Dispersed Facts", "Breaks Multi Step Deductive Chains"]]
    ],
    [
        [["Single Needle Lookup", "Insert Isolated Target In Arbitrary Haystack", "Evaluates Baseline Keyword Grounding"], ["Multi Needle Synthesis", "Scattered Interdependent Fact Fragments", "Tests Cross Document Association Capacity"]],
        [["Distractor Interference", "Semantically Similar Falsehoods In Context", "Measures Resistance To False Latching"], ["Multi Hop Horizon", "Logical Deductions Spanning Dispersed Pages", "Determines Complex Reasoning Boundaries"]],
        [["Heat Map Profiling", "Two Dimensional Depth By Length Accuracy Plot", "Reveals Latent Attention Degradation Pockets"], ["Synthetic Stress Test", "Automated Parameterized Fact Injections", "Validates Prompt Optimization Resilience"]],
        [["Zero Tolerance Scoring", "Deterministic Ground Truth String Verification", "Prevents Production Metric Hallucination"], ["Semantic Gap Metric", "Embedding Distance Between Needle And Context", "Calibrates True Retrieval Difficulty"]]
    ],
    [
        [["Primacy Sandwich Pattern", "Critical Rules At Head And Target Task At Tail", "Maximizes Attention On Crucial Directives"], ["XML Boundary Tagging", "Explicit Document Tags With Metadata Attributes", "Enables Unambiguous Source Attribution"]],
        [["Salience Ordering", "Rank Chunks And Place Low Priority In Middle", "Protects Critical Insights From Decay"], ["Context Deduplication", "Eliminate Boilerplate And Repeated Content", "Preserves Informational Token Entropy"]],
        [["Iterative Compaction", "Summarize Historical Tool Calls Into States", "Maintains Lean Low Latency Context"], ["JSON Table Serialization", "Convert Tabular Matrices Into Key Value Pairs", "Prevents Column To Value Misalignment"]],
        [["Privacy Redaction Gate", "Filter Sensitive Markers Before Ingestion", "Enforces Regulatory Compliance Boundaries"], ["Dynamic Chunk Sizing", "Adaptive Boundary Partitioning By Topic", "Eliminates Mid Concept Semantic Fractures"]]
    ],
    [
        [["Token Budget Governor", "Precise Token Counting And Limit Enforcement", "Prevents Context Window Overflow Errors"], ["Salience Layout Compiler", "Algorithmic Partitioning Into Placement Queues", "Guarantees Polar Attention Allocation"]],
        [["Prefix Caching Optimizer", "Standardize Primary Directive Text Blocks", "Cuts Operational Costs And Latencies"], ["Degradation Cascade", "Adaptive Middle Pruning Upon Volume Spikes", "Prevents Pipeline Crashing Under Load"]],
        [["OpenTelemetry Tracer", "Track Depth Latency And Retrieval Accuracy", "Provides Real Time Observability"], ["Audit Provenance Ledger", "Cryptographic Hash Of Compiled Prompt State", "Ensures Full Institutional Compliance"]],
        [["Automated SLA Watchdog", "Sub Second Retrieval Tail Latency Targets", "Maintains Consistent Enterprise Uptime"], ["Dynamic Worker Cluster", "Isolated Distributed Context Compilers", "Guarantees High Concurrency Throughput"]]
    ]
]

# Verify lengths and digits
for p_idx, cap_dict in enumerate(captions_data):
    for k, text_str in cap_dict.items():
        assert len(text_str) <= 75, f"Part {p_idx+1} {k} caption too long: {len(text_str)} ({text_str})"
        assert text_str.endswith('.'), f"Part {p_idx+1} {k} caption must end with dot: {text_str}"
        assert not any(c.isdigit() for c in text_str), f"Part {p_idx+1} {k} caption has digits: {text_str}"

for t in titles:
    assert len(t) <= 75, f"Title too long: {len(t)} ({t})"
    assert t.endswith('.'), f"Title must end with dot: {t}"
    assert not any(c.isdigit() for c in t), f"Title has digits: {t}"

for cols in columns_list:
    for c in cols:
        assert not any(ch.isdigit() for ch in c), f"Column has digits: {c}"

for step_row in steps_rows:
    for row in step_row:
        for pair in row:
            for cell in pair:
                assert not any(ch.isdigit() for ch in cell), f"Cell has digits: {cell}"

entries = []
for p_idx, part in enumerate(parts_data):
    spec_steps = []
    for s_idx, at_k in enumerate(["say1", "say2", "example", "tryIt"]):
        cap = captions_data[p_idx][at_k]
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
    assert len(spec['title']) <= 75, f"Title too long: {spec['title']}"
    assert spec['title'].endswith('.'), f"Title must end with dot: {spec['title']}"
    assert not any(c.isdigit() for c in spec['title']), f"Title has digits: {spec['title']}"
    
    code_hash = hashlib.sha256(part['code'].encode('utf-8')).hexdigest()
    entry = {
        "partTitle": part['title'],
        "codeHash": code_hash,
        "spec": spec,
        "filled": spec
    }
    entries.append(entry)

visual_envelope = {
    "schemaVersion": "2.0.0",
    "course": "prompt-py",
    "day": 34,
    "prefix": "prompt-py",
    "entries": entries
}

# Write lesson JSON
with open('C:/Users/Admin/Desktop/projects/Present-Career-os-platform/scripts/branch_c/prompt_day34_lesson.json', 'w', encoding='utf-8') as f:
    json.dump(day34_dict, f, indent=2)

# Write visual envelope
with open('C:/Users/Admin/Desktop/projects/Present-Career-os-platform/src/lib/data/lessonVisuals/prompt-py/day-34.json', 'w', encoding='utf-8') as f:
    json.dump(visual_envelope, f, indent=2)

print(f"Generated Day 34 lesson JSON ({total_words} words) and Visual Envelope successfully!")
