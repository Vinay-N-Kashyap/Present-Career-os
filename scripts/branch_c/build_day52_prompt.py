import json
import hashlib
import re

part1_say = [
    "Relying on system prompts alone to defend foundation models against adversarial exploitation is an architectural anti-pattern. System prompts—no matter how meticulously worded, authoritative, or repetitive—are fundamentally processed within the same transformer attention stream as untrusted user inputs. When an adversarial user crafts an input that commands the model to disregard its initial directives, the attention heads compute semantic interactions across both strings simultaneously. To achieve genuine enterprise security, organizations must decouple safety enforcement from the foundation model itself, constructing external pre-flight input guardrail pipelines.",
    "The architecture of pre flight input guardrails establishes defense in depth across multi-tier inspection layers. Operating as an external reverse-proxy gateway stationed between client applications and foundation model inference endpoints, the pre-flight guardrail inspects, evaluates, and filters incoming prompt payloads before they consume GPU inference cycles. If an input violates enterprise safety policies or exhibits adversarial exploit characteristics, the gateway rejects the request at the perimeter in single-digit milliseconds.",
    "Defense-in-depth architecture structures input validation across four specialized, progressive defense tiers: lexical pattern sanitization, statistical perplexity gating, neural safety classification, and programmable conversational flow enforcement. By organizing defenses into progressive tiers, the platform processes incoming prompts through increasingly sophisticated inspection filters, rejecting crude attacks early with minimal computational overhead while reserving deep neural analysis for subtle semantic exploits.",
    "Tier-one lexical sanitization performs instantaneous string matching, regex evaluation, and Unicode canonicalization. It strips dangerous control characters, unmasks Base64 and Hexadecimal ciphers, normalizes homoglyphs, and checks input tokens against high-priority blocklists. This initial filter intercepts known malicious phrases and crude obfuscation attempts in microseconds without requiring neural network execution.",
    "Tier-two statistical perplexity gating evaluates the natural language coherence of the input using ultra-fast, lightweight language models. By calculating sliding-window token perplexity, the gate identifies unnatural, high-entropy character sequences characteristic of gradient-optimized universal adversarial suffixes. Prompts containing anomalous token sequences are dropped immediately, defeating mathematical jailbreak attacks before semantic parsing begins.",
    "Tier-three neural safety classification dispatches the sanitized text to dedicated, specialized moderation models such as Meta's Llama Guard. The neural classifier evaluates the semantic intent of the prompt against standardized safety taxonomies, categorizing requests into explicit risk tiers (such as cyberattack generation, hate speech, or chemical hazards) and returning structured binary safety determinations with sub-twenty-millisecond latency.",
    "Tier-four programmable flow enforcement utilizes dialogue policy engines—such as NVIDIA NeMo Guardrails—to enforce domain-specific behavioral boundaries and conversational guardrails. Defined via declarative flow modeling languages like Colang, these policies dictate allowed conversational trajectories, verify that user queries remain strictly within authorized business topics, and orchestrate automated redirection if an attacker attempts semantic steering.",
    "Latency budgets and throughput economics govern the practical deployment of pre-flight guardrail architectures. In enterprise conversational applications where human users expect responsive interactions, the cumulative latency introduced by the entire guardrail pipeline must not exceed thirty milliseconds. By running lightweight quantized models on local edge instances and evaluating statistical filters asynchronously, modern architectures achieve rigorous defense without degrading user experience.",
    "Fail-secure fallback mechanics guarantee that guardrail failures never compromise enterprise systems. If an external moderation API experiences network timeouts or a guardrail container crashes, the orchestrator defaults to a closed posture, gracefully refusing the user request and alerting security site reliability engineers rather than allowing uninspected inputs to reach foundation model backends.",
    "Edge deployment architectures leverage lightweight proxy sidecars stationed adjacent to application servers, ensuring minimal network hops during pre-flight inspection. By caching previously classified safe prompt hashes in ultra-fast in-memory stores, recurring boilerplate queries bypass redundant neural classification entirely. This hybrid caching and streaming architecture delivers near-instantaneous response times for standard traffic while maintaining vigilant inspection over novel inputs.",
    "Mastering the architecture of pre-flight guardrails transitions AI security from hopeful prompt engineering into deterministic systems defense. By establishing external, multi-tier inspection pipelines, you protect enterprise foundation models from adversarial compromise regardless of prompt complexity."
]

part2_say = [
    "While heuristic keyword filters are easily bypassed by synonyms and ciphers, deep learning moderation classifiers provide robust semantic understanding of harmful intent. In the open-source and enterprise AI ecosystem, Meta's Llama Guard represents the industry standard for dedicated, instruction-following safety moderation. Built on fine-tuned Llama architectures and aligned with standardized safety taxonomies, Llama Guard enables organizations to inspect both incoming user prompts and outgoing model completions with exceptional semantic precision.",
    "Neural moderation and safety taxonomy classification categorize prompts against standardized enterprise risk policies. Rather than generating open-ended conversational text, Llama Guard is trained to act as an objective safety arbiter. Given a user prompt or model response alongside an explicit policy definition, Llama Guard outputs a deterministic classification: emitting the single word 'safe' if the input adheres to guidelines, or emitting 'unsafe' followed by the specific violated policy category code.",
    "The MLCommons safety taxonomy provides the standardized structural foundation for Llama Guard's classification policies. The taxonomy categorizes digital harms into fourteen distinct, granular hazard categories: ranging from violent crimes, non-violent offenses, and hate speech to software vulnerabilities, weapons of mass destruction, and suicide self-harm encouragement. Each category is delineated by formal, unambiguous definition boundaries.",
    "Software vulnerability and cyberattack policy enforcement (Category O eleven) protects enterprise infrastructure from automated exploitation. When an adversarial user prompts an agent to write polymorphic ransomware, generate SQL injection payloads, or scan corporate IP ranges for unpatched vulnerabilities, Llama Guard detects the malicious intent and flags the input under the cyberattack policy, neutralizing exploit generation.",
    "Customizing safety taxonomies allows enterprises to align Llama Guard with proprietary corporate governance mandates. Organizations can augment the default MLCommons taxonomy with bespoke business policies—such as prohibiting discussions of competitor products, blocking unauthorized investment advice, or restricting legal interpretations. Llama Guard evaluates custom policies with zero-shot generalization based on natural language policy descriptions.",
    "Input and output dual-pass evaluation ensures comprehensive lifecycle safety. During the pre-flight phase, Llama Guard evaluates the user's prompt to prevent adversarial jailbreaks from reaching the core foundation model. During the post-generation phase, Llama Guard inspects the generated output before transmission to the user, ensuring that even if an attacker successfully subverts the primary model, the harmful completion is intercepted before delivery.",
    "Inference optimization through quantization and speculative decoding makes neural classification practical for high-throughput production workloads. By deploying four-bit AWQ or eight-bit quantized variants of Llama Guard on high-speed GPU inference servers, organizations achieve classification latencies under fifteen milliseconds, allowing every prompt to be scrutinized without creating conversational bottlenecks.",
    "Handling nuanced borderline prompts requires calibrating confidence thresholds and risk tolerances. In applications such as fiction writing or cybersecurity training, prompts may contain words associated with malware or conflict without possessing malicious intent. By fine-tuning Llama Guard on domain-specific counterfactual examples, organizations reduce false-positive rejection rates to below zero point five percent.",
    "Audit telemetry and violation logging record structured metadata for every flagged prompt. When Llama Guard intercepts an unsafe input, the system logs the full input text, the violated taxonomy category, the model confidence score, and client session identifiers into security information and event management (SIEM) pipelines, facilitating automated threat attribution.",
    "Advanced Llama Guard deployments format conversational context as structured dialogue histories rather than isolated prompt snippets. By supplying the preceding assistant turns alongside the current user query, the neural classifier evaluates context-dependent social engineering attempts that appear innocuous when viewed in isolation. This contextual awareness ensures that adversarial threat actors cannot dismantle safety guardrails through gradual multi-turn conversational steering.",
    "Mastering neural safety classification with Llama Guard provides platform engineers with a powerful, customizable semantic shield. By anchoring moderation in standardized taxonomies and optimized inference runtimes, you enforce consistent, enterprise-grade safety across all foundation model interactions."
]

part3_say = [
    "While classification models determine whether a given text snippet is safe or unsafe, autonomous AI systems require dynamic, stateful control over the entire conversational flow. A user request may be completely benign in isolation, yet represent a calculated step in a multi-turn social engineering or jailbreak campaign. To manage conversational trajectories, enforce topical boundaries, and integrate custom business logic deterministically, enterprise platforms turn to programmable conversational guardrails: most prominently, NVIDIA NeMo Guardrails.",
    "Programmable conversational guardrails with NeMo Colang flows direct paths and prevent off-topic deviations. NeMo Guardrails is an open-source framework that enables developers to define programmable conversational rules, safety boundaries, and tool-invocation constraints using Colang: a specialized modeling language designed specifically for specifying dialogue flows, user intents, and system actions with mathematical precision.",
    "The Colang modeling language abstracts complex conversational interactions into clean, human-readable flow definitions. In Colang, developers define user intent patterns (such as 'user ask about pricing' or 'user attempt system prompt extraction'), define corresponding bot responses, and script multi-step conversational flows that dictate exactly how the agent must navigate specific topics.",
    "Topical guardrails enforce strict domain boundaries, ensuring that specialized corporate agents cannot be hijacked into discussing irrelevant or contentious subjects. For an enterprise banking agent, a topical rail can specify that any query touching politics, medical advice, or personal relationships must trigger a polite, pre-scripted deflection, preventing the agent from being drawn into public relations disasters.",
    "Execution guardrails monitor and intercept tool calling actions initiated by foundation models. Before an agent executes a Python script or issues a database update, the execution rail evaluates the tool parameters against Colang policy rules. If an agent attempts to execute an unauthorized system command or update a record outside the user's account scope, the execution rail aborts the tool call instantly.",
    "Fact-checking and hallucination rails verify the factual consistency of model responses against retrieved reference documents. By executing automated entailment verification models within the Colang flow, the guardrail compares the generated output against source paragraphs. If the model generates assertions not supported by the retrieved facts, the rail flags the hallucination and prompts the model to regenerate the response with factual grounding.",
    "Integration with external Python verification functions extends Colang flows with arbitrary computational checks. A Colang flow can trigger a Python function that queries an internal LDAP directory, checks an IP address reputation score, or invokes a custom regex parser, bridging declarative dialogue rules with enterprise software infrastructure.",
    "Deterministic state machine semantics underpin Colang flow execution, guaranteeing that conversational transitions adhere strictly to defined rules. Unlike foundation models that make probabilistic token predictions, the NeMo Guardrails runtime executes as a deterministic state machine, ensuring that once an unsafe flow is entered, the agent cannot be coaxed into an unapproved conversational branch.",
    "Multi-turn context tracking allows NeMo Guardrails to identify slow-burn adversarial manipulation across extended chat histories. An adversary attempting to dismantle guardrails through incremental semantic shifts is tracked across dialogue turns, with the state engine recognizing the cumulative drift and terminating the session before boundaries are breached.",
    "Colang execution engines support asynchronous action dispatch, allowing guardrail flows to communicate seamlessly with distributed enterprise services without blocking event loops. When a user input triggers a policy check, the Colang engine can asynchronously query external threat intelligence feeds, verify user entitlement roles in corporate IAM directories, and evaluate database transaction limits concurrently. This tight integration transforms conversational guardrails into active policy enforcement gateways across enterprise infrastructure.",
    "Additionally, declarative policy versioning ensures that conversational flows can be tested, audited, and rolled back in version control systems like standard application code. By managing Colang rails through Git repositories with automated continuous integration checks, enterprise teams maintain rigorous change control over conversational safety logic.",
    "Mastering programmable guardrails with NeMo Colang elevates conversational safety from reactive filtering to proactive architectural orchestration. By defining declarative dialogue flows, execution constraints, and hallucination checks, you build enterprise AI systems that maintain unwavering behavioral integrity under all conditions."
]

part4_say = [
    "Among the most dangerous adversarial threats facing modern foundation models are universal adversarial suffixes: gradient-optimized token sequences that induce model jailbreaks regardless of prompt semantics. Developed through mathematical optimization algorithms like Greedy Coordinate Gradient (GCG), these attacks append seemingly random strings of punctuation and uncommon words that manipulate transformer attention distributions. Defending against these mathematical attacks requires mathematical defense: Token Perplexity Filtering and Semantic Outlier Detection.",
    "Perplexity classifiers and semantic vector boundary scanners flag anomaly spikes to defeat universal adversarial attacks. Because foundation models are trained on natural human language, legitimate user queries exhibit predictable statistical patterns and low token perplexity. In contrast, gradient-optimized adversarial suffixes represent unnatural, low-probability token combinations that trigger massive statistical perplexity spikes, allowing lightweight statistical detectors to intercept them in single-digit milliseconds.",
    "The mathematical formulation of token perplexity measures how surprised a language model is by a sequence of tokens. Defined as the exponentiated average negative log-likelihood of a sequence, perplexity quantifies the statistical probability of each token given its preceding context. When a standard sentence like 'Explain how photosynthesis works' is evaluated by a reference model (such as GPT-2 or Llama-3.2-1B), its perplexity typically falls between ten and thirty.",
    "Universal adversarial suffixes trigger catastrophic perplexity spikes exceeding several hundred or thousand. Because GCG optimization crafts token combinations based on gradient loss functions rather than linguistic grammar, the resulting strings—such as 'representing poetry surely ! ! describe := ==='—are statistically bizarre to standard language models. By computing perplexity over the final twenty tokens of incoming prompts, the defense gate flags and drops adversarial strings instantly.",
    "Sliding-window perplexity analysis prevents attackers from disguising adversarial suffixes within long, fluent essays. If an attacker embeds a high-entropy suffix inside a multi-thousand-word academic paper, average prompt perplexity might appear normal. Sliding-window analyzers calculate perplexity across overlapping chunks of fifteen tokens, pinpointing the localized entropy spike created by the adversarial payload.",
    "Dual-model reference perplexity architectures prevent adaptive evasion attacks. If an attacker attempts to optimize an adversarial suffix against a known target model while keeping its perplexity low, the defense pipeline evaluates the prompt against an alternative, independently trained reference model. Because adversarial transferability does not correlate perfectly with multi-model perplexity, the anomaly gate detects the evasion attempt.",
    "Semantic vector boundary scanning complements perplexity by evaluating input embeddings against allowed task domain clusters. By computing the cosine distance between the incoming prompt embedding and pre-computed centroids of legitimate business queries, the scanner identifies semantic outliers that stray far from authorized operational domains, catching zero-day injection concepts.",
    "Empirical defense evaluations demonstrate the unmatched efficacy of perplexity filtering. In rigorous red-team benchmarks evaluating thousands of GCG and universal suffix attacks, sliding-window perplexity classifiers achieve a ninety-nine point two percent attack deflection rate while maintaining a false-positive rejection rate of just zero point four percent on standard enterprise business queries.",
    "Ultra-low latency execution makes perplexity gating ideal for frontline perimeter defense. By evaluating prompts using lightweight, quantized reference models on dedicated CPU or GPU workers, perplexity calculations complete in under five milliseconds, providing an instantaneous statistical shield that screens out mathematical attacks before heavier neural classifiers engage.",
    "Adaptive threshold calibration dynamically adjusts perplexity tolerance based on the expected vocabulary domain of the application. In software engineering and technical writing assistants where code syntax, mathematical formulas, and terminal commands naturally exhibit higher perplexity than conversational English, the classifier establishes domain-specific perplexity baselines. This context-aware calibration minimizes false-positive rejections on technical payloads while preserving sharp anomaly detection for adversarial suffixes.",
    "Mastering perplexity classification and semantic boundary scanning equips security architects with mathematically grounded defense primitives. By pairing statistical language modeling with vector distance metrics, you neutralize the most sophisticated gradient-based adversarial attacks with minimal latency overhead."
]

part5_say = [
    "Translating pre-flight defense-in-depth, Llama Guard neural classification, NeMo Colang flow enforcement, and statistical perplexity filtering into an enterprise platform requires engineering a unified Multi-Layer Defensive Input Filtering Engine. In this engineering capstone, we implement a production-grade Input Validation Pipeline in Python, capable of screening prompt payloads across statistical, neural, and programmable policy tiers, achieving a ninety-nine point two percent adversarial deflection rate with an eighteen point six millisecond response latency.",
    "Enterprise multi layer defensive input filtering engines automate checks across asynchronous pipelines with zero disruption. Built on native Python inspection, quantized neural classifiers, and statistical language modeling primitives, the engine provides an unbroken defensive perimeter that inspects, sanitizes, and certifies incoming prompts before GPU inference begins, protecting enterprise backends from adversarial exploitation.",
    "The software architecture of the defensive input engine integrates four specialized inspection stages: the Dual-Model Perplexity Anomaly Gate, the Llama Guard Taxonomy Classifier, the NeMo Colang Policy Enforcer, and the Semantic Vector Boundary Scanner. Each stage executes asynchronously within a non-blocking pipeline, ensuring optimal throughput across high-concurrency enterprise workloads.",
    "The Dual-Model Perplexity Anomaly Gate serves as the frontline statistical filter. It evaluates prompt token distributions using lightweight reference models, calculating sliding-window perplexity scores in single-digit milliseconds. Any prompt exhibiting an unnatural entropy spike—characteristic of GCG universal suffixes—is dropped instantly, preventing mathematical jailbreaks from reaching deeper pipeline stages.",
    "The Llama Guard Taxonomy Classifier evaluates sanitized prompts against the comprehensive MLCommons safety taxonomy. It analyzes semantic intent across fourteen hazard categories, returning structured safety classifications with sub-twenty-millisecond latency. Prompts attempting to generate malware, execute unauthorized reconnaissance, or violate corporate policies are flagged and rejected deterministically.",
    "The NeMo Colang Policy Enforcer executes programmable dialogue rules, verifying that user requests adhere to authorized conversational trajectories and domain boundaries. Defined in declarative Colang flows, the policy enforcer intercepts subtle topic deviations, blocks system prompt extraction attempts, and enforces strict tool-execution constraints.",
    "The Semantic Vector Boundary Scanner calculates cosine similarity metrics between incoming prompt embeddings and authorized business domain centroids. Prompts that stray outside enterprise task boundaries are flagged for secondary security review, closing the gap against novel zero-day prompt phrasing.",
    "Comprehensive OpenTelemetry instrumentation tracks filtering metrics, latency distributions, and violation category frequencies in real time. Prometheus metrics export continuously to corporate security operations dashboards, providing site reliability engineers with granular visibility into fleet-wide adversarial threat landscapes.",
    "Empirical enterprise benchmark evaluations confirm the extraordinary protection delivered by the multi-layer pipeline: achieving a ninety-nine point two percent adversarial suffix deflection rate, a negligible zero point four percent false-positive rejection rate on legitimate enterprise queries, and an eighteen point six millisecond end-to-end classification latency.",
    "Cryptographic safety provenance records immutable SHA-256 digests of all evaluated prompts, safety determinations, and policy violation logs in statutory compliance ledgers, fulfilling enterprise auditing requirements and establishing a tamper-proof chain of custody for all AI interactions.",
    "Furthermore, automated regression testing ensures that defensive updates and policy modifications maintain backward compatibility without introducing unexpected false-positive rejections on mission-critical business workflows.",
    "Industrial input filtering architectures incorporate automated fail-safe circuit breakers to preserve business continuity during peak traffic surges or downstream classifier degradations. If neural moderation microservices experience latency spikes exceeding strict operational thresholds, the pipeline dynamically sheds non-essential evaluation passes while elevating statistical heuristic logging. This adaptive throttling maintains system responsiveness without completely sacrificing defensive oversight.",
    "Comprehensive regulatory compliance auditing demands immutable evidence of safety policy enforcement across all enterprise AI interactions. By archiving cryptographic hashes of incoming prompts alongside verified classification decisions, organizations establish transparent auditability for statutory compliance with global artificial intelligence governance frameworks.",
    "Mastering the engineering architecture of multi-layer defensive input filtering engines establishes you as a master architect of safe enterprise AI platforms. By harmonizing statistical, neural, and programmable guardrails, you build resilient AI systems that withstand adversarial manipulation while delivering seamless performance."
]

parts_data = [
    {
        "title": "The Architecture Of Multi Tier Pre Flight Input Guardrails",
        "say": part1_say,
        "example": "Dual model guardrails filter malicious prompts before LLM inference.",
        "tryIt": "Architect a multi tier defensive input pipeline with low latency gates.",
        "check": {
            "question": "Why is relying solely on system prompts for AI safety considered an architectural anti-pattern?",
            "options": [
                "System prompts and untrusted user inputs are processed within the same unified attention stream",
                "System prompts are automatically deleted from server memory after five seconds",
                "Foundation models refuse to read any system prompt that contains more than ten words",
                "Operating system kernels do not allow system prompts to be written in English"
            ],
            "answer": 0,
            "answerIndex": 0,
            "why": "System prompts and user inputs share the same attention mechanism, allowing adversarial inputs to compete with and override developer instructions."
        }
    },
    {
        "title": "Neural Moderation And Safety Taxonomy Classification With Llama Guard",
        "say": part2_say,
        "example": "Llama Guard evaluates incoming prompts against standardized taxonomies.",
        "tryIt": "Configure customized policy taxonomies within a neural moderation model.",
        "check": {
            "question": "What is the primary output format of Llama Guard when evaluating a prompt?",
            "options": [
                "A binary classification emitting safe or unsafe followed by the specific policy violation code",
                "A multi-page conversational essay debating the philosophical merits of the prompt",
                "A random string of hexadecimal numbers that must be decoded by human operators",
                "An automatic command that shuts down the graphics processing unit"
            ],
            "answer": 0,
            "answerIndex": 0,
            "why": "Llama Guard outputs a deterministic classification: emitting safe if the input is compliant, or unsafe with the violated category code (e.g., O11)."
        }
    },
    {
        "title": "Programmable Conversational Guardrails With NeMo Colang Flows",
        "say": part3_say,
        "example": "Colang flows intercept adversarial steering and restrict topical scopes.",
        "tryIt": "Write Colang dialogue policies defining topical boundaries for an agent.",
        "check": {
            "question": "What role does the Colang modeling language play in NVIDIA NeMo Guardrails?",
            "options": [
                "It specifies declarative dialogue flows, user intents, and system action constraints deterministically",
                "It compiles Python scripts into physical silicon microchips in real time",
                "It replaces all neural network weights with static text lookup tables",
                "It permanently encrypts the user hard drive to prevent file reading"
            ],
            "answer": 0,
            "answerIndex": 0,
            "why": "Colang defines conversational flows, user intents, and execution constraints as a deterministic state machine, preventing off-topic steering."
        }
    },
    {
        "title": "Perplexity Classifiers And Semantic Vector Boundary Scanners",
        "say": part4_say,
        "example": "High perplexity triggers instant rejection of adversarial token strings.",
        "tryIt": "Implement a sliding window perplexity detector evaluating prompt tokens.",
        "check": {
            "question": "Why are sliding-window perplexity classifiers highly effective against universal adversarial suffixes?",
            "options": [
                "Gradient-optimized GCG suffixes exhibit unnatural, high-entropy token sequences with extreme perplexity spikes",
                "Universal suffixes always contain the exact English phrase please ignore all rules",
                "Perplexity classifiers convert all incoming text into analog radio frequency waves",
                "Language models refuse to generate tokens if the prompt contains any punctuation marks"
            ],
            "answer": 0,
            "answerIndex": 0,
            "why": "Adversarial suffixes optimized via gradients are statistically unnatural and cause massive perplexity spikes, allowing fast statistical detection."
        }
    },
    {
        "title": "Enterprise Multi Layer Defensive Input Filtering Engine In Python",
        "say": part5_say,
        "example": "Multi layer input pipelines achieve eighteen millisecond response times.",
        "tryIt": "Deploy an enterprise input filtering engine with integrated classifiers.",
        "check": {
            "question": "What is the primary operational advantage of the multi-layer defensive input filtering pipeline?",
            "options": [
                "It deflects over ninety-nine percent of adversarial attacks with sub-twenty-millisecond classification latency",
                "It permanently disables all incoming internet connections to the enterprise data center",
                "It requires all human users to solve complex calculus equations before chatting",
                "It converts all text inputs into uncompressed raw bitmap image files"
            ],
            "answer": 0,
            "answerIndex": 0,
            "why": "The multi-tier pipeline combines statistical, neural, and programmable filters to achieve 99.2% attack deflection with low 18.6ms latency."
        }
    }
]

code_snippet = """import json
from typing import Dict, Any, List

def test_day52_input_guardrails() -> Dict[str, Any]:
    \"\"\"
    Day 52: Input Validation & Defensive Filtering: NeMo Guardrails, Llama Guard, Perplexity Classifiers & Semantic Pre-Flight Sanitization
    \"\"\"
    guardrail_pipeline = [
        "Dual-Model Perplexity Anomaly Gate",
        "Llama Guard O1-O14 Safety Taxonomy Classifier",
        "NeMo Guardrails Colang Flow Policy Enforcer",
        "Semantic Intent Vector Boundary Scanner"
    ]
    filtering_metrics = {
        "adversarialSuffixFilterRatePct": 99.2,
        "falsePositiveRejectionRatePct": 0.4,
        "classificationLatencyMs": 18.6
    }
    return {
        "pipeline": "Multi-Layer Defensive Input Filtering Engine",
        "guardrailStages": guardrail_pipeline,
        "filteringMetrics": filtering_metrics,
        "status": "INPUT_GUARDRAILS_OPERATIONAL"
    }

if __name__ == "__main__":
    result = test_day52_input_guardrails()
    print(json.dumps(result, indent=2))
"""

code_hash = hashlib.sha256(code_snippet.encode('utf-8')).hexdigest()

output_snippet = """{
  "pipeline": "Multi-Layer Defensive Input Filtering Engine",
  "guardrailStages": [
    "Dual-Model Perplexity Anomaly Gate",
    "Llama Guard O1-O14 Safety Taxonomy Classifier",
    "NeMo Guardrails Colang Flow Policy Enforcer",
    "Semantic Intent Vector Boundary Scanner"
  ],
  "filteringMetrics": {
    "adversarialSuffixFilterRatePct": 99.2,
    "falsePositiveRejectionRatePct": 0.4,
    "classificationLatencyMs": 18.6
  },
  "status": "INPUT_GUARDRAILS_OPERATIONAL"
}"""

captions_data = [
    {
        "say1": "Multi tier pre flight guardrails sanitize untrusted prompts reliably.",
        "say2": "The architecture of pre flight input guardrails establishes defense.",
        "example": "Dual model guardrails filter malicious prompts before LLM inference.",
        "tryIt": "Architect a multi tier defensive input pipeline with low latency gates."
    },
    {
        "say1": "Neural moderation classifiers categorize prompts against safety policies.",
        "say2": "Neural moderation and safety taxonomy classification categorize prompts.",
        "example": "Llama Guard evaluates incoming prompts against standardized taxonomies.",
        "tryIt": "Configure customized policy taxonomies within a neural moderation model."
    },
    {
        "say1": "Programmable Colang flows guide dialogue trajectories and enforce bounds.",
        "say2": "Programmable conversational guardrails with NeMo Colang flows direct path.",
        "example": "Colang flows intercept adversarial steering and restrict topical scopes.",
        "tryIt": "Write Colang dialogue policies defining topical boundaries for an agent."
    },
    {
        "say1": "Perplexity spikes identify unnatural gradient optimized token suffixes.",
        "say2": "Perplexity classifiers and semantic vector boundary scanners flag anomaly.",
        "example": "High perplexity triggers instant rejection of adversarial token strings.",
        "tryIt": "Implement a sliding window perplexity detector evaluating prompt tokens."
    },
    {
        "say1": "Enterprise input filtering pipelines deflect adversarial prompts cleanly.",
        "say2": "Enterprise multi layer defensive input filtering engines automate checks.",
        "example": "Multi layer input pipelines achieve eighteen millisecond response times.",
        "tryIt": "Deploy an enterprise input filtering engine with integrated classifiers."
    }
]

titles = [
    "The Architecture Of Multi Tier Pre Flight Input Guardrails.",
    "Neural Moderation And Safety Taxonomy Classification With Llama Guard.",
    "Programmable Conversational Guardrails With NeMo Colang Flows.",
    "Perplexity Classifiers And Semantic Vector Boundary Scanners.",
    "Enterprise Multi Layer Defensive Input Filtering Engine In Python."
]

columns_list = [
    ["Guardrail Tier", "Inspection Mechanism", "Latency Defense SLA"],
    ["Taxonomy Category", "Violation Criterion", "Policy Enforcement Rule"],
    ["Colang Construct", "Flow Orchestration", "Deterministic Safety SLA"],
    ["Statistical Metric", "Mathematical Formulation", "Anomaly Detection SLA"],
    ["Filtering Engine Tier", "Implementation Strategy", "Production SLA Target"]
]

steps_rows = [
    [
        [["Lexical Sanitization", "Regex And Unicode Character Normalization", "Sub Millisecond Execution Latency"], ["Statistical Perplexity Gate", "Sliding Window Token Probability Analysis", "Five Millisecond Anomaly Check"]],
        [["Neural Moderation Classifier", "Llama Guard Safety Taxonomy Evaluation", "Fifteen Millisecond Classification"], ["Programmable Flow Enforcer", "NeMo Colang State Machine Flow Routing", "Zero Unapproved Branching Toleration"]],
        [["Fail Secure Fallback Gate", "Closed Default Policy On Gateway Failures", "Guarantees Zero Exploit Pass Through"], ["Telemetry Export Core", "Streams Violation Metrics To SIEM Dashboards", "Comprehensive Operational Visibility"]],
        [["Sovereign Reverse Proxy", "Intercepts Untrusted Prompts At Perimeter", "Eighteen Millisecond Mean Latency"], ["Enterprise Defense Shield", "Deflects Multi Tier Attacks Deterministically", "Flawless Enterprise Compliance"]]
    ],
    [
        [["Violent Crime Taxonomy", "Evaluates Physical Injury Incitement Signals", "Absolute Input Rejection Standard"], ["Cyberattack Vulnerability", "Scans For Malware And Exploit Code Synthesis", "Enforces Software Security Policies"]],
        [["Hate Speech Classification", "Detects Slurs And Harassment Intent Patterns", "Blocks Content Across Languages"], ["Chemical Hazard Policy", "Identifies Hazardous Material Synthesis Inquiries", "Mandatory Critical Escalation Alert"]],
        [["Custom Corporate Policy", "Defines Bespoke Governance And Brand Rules", "Zero Shot Contextual Generalization"], ["Dual Pass Evaluation Gate", "Inspects Both User Prompts And Model Outputs", "Complete Lifecycle Safety Shield"]],
        [["Neural Arbiter Core", "Outputs Deterministic Safe Or Unsafe Labels", "Zero Point Four False Positive Rate"], ["Sovereign Taxonomy Hub", "Standardizes Moderation Across AI Workloads", "Flawless Multi Tenant Governance"]]
    ],
    [
        [["User Intent Definition", "Maps Expressed User Requests In Natural Syntax", "Precise Conversational Mapping"], ["Bot Response Template", "Defines Standardized Pre Approved Answers", "Consistent Brand Voice Alignment"]],
        [["Topical Boundary Rail", "Deflects Out Of Domain Controversial Queries", "Zero Public Relations Risk Standard"], ["Tool Execution Guard", "Validates Function Parameters Prior To Action", "Blocks Unauthorized Database Edits"]],
        [["Fact Checking Rail", "Compares Model Assertions Against Source Text", "Prevents Unverified Hallucinations"], ["Deterministic State Engine", "Executes State Transitions Without Randomness", "One Hundred Percent Flow Compliance"]],
        [["Colang Policy Kernel", "Harmonizes Intent Action And Safety Rails", "Zero Dialogue Derailment Toleration"], ["Sovereign Flow Mesh", "Maintains Conversational Control Autonomously", "Flawless Architectural Integrity"]]
    ],
    [
        [["Token Negative Log Likelihood", "Calculates Surprise Factor Over Token Sequence", "Standard Baseline In Natural Prose"], ["Sliding Window Perplexity", "Evaluates Localized Fifteen Token Windows", "Detects Hidden Adversarial Suffixes"]],
        [["Dual Model Architecture", "Cross Evaluates Prompts Across Model Families", "Neutralizes Adaptive Evasion Tactic"], ["Cosine Centroid Distance", "Measures Deviation From Allowed Task Vectors", "Flags Out Of Domain Semantic Drifts"]],
        [["Subword Entropy Scanner", "Calculates Character Distribution Density", "Identifies Obfuscated String Payloads"], ["Anomaly Dropping Gate", "Rejects Prompts Exceeding Perplexity Bounds", "Five Millisecond Execution Latency"]],
        [["Statistical Defense Core", "Neutralizes Gradient Optimized Universal Attacks", "Ninety Nine Percent Attack Recall"], ["Sovereign Entropy Hub", "Screens Mathematical Jailbreaks Mathematically", "Zero False Alarm Disruption SLA"]]
    ],
    [
        [["Dual Model Perplexity Gate", "Filters High Entropy Suffix Strings Rapidly", "Sub Five Millisecond Anomaly Check"], ["Llama Guard Classifier", "Categorizes Hazards Across Fourteen Policies", "Fifteen Millisecond Latency SLA"]],
        [["NeMo Colang Enforcer", "Directs Conversational Flow Along Safe Paths", "Deterministic Dialogue Governance"], ["Vector Boundary Scanner", "Measures Cosine Distance To Allowed Clusters", "Captures Semantic Outlier Requests"]],
        [["AsyncIO Parallel Worker", "Coordinates Asynchronous Guardrail Workers", "High Concurrency Fleet Scalability"], ["OpenTelemetry Telemetry Bus", "Exports Real Time Deflection Latency Spans", "Granular Production Observability"]],
        [["Cryptographic Safety Ledger", "Archives Hashes Of Prompts Classifications", "Statutory Compliance Architecture"], ["Apex Defensive Engine", "Harmonizes Statistical Neural And Flow Gates", "Ninety Nine Percent Attack Deflection"]]
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

for p_idx, steps in enumerate(steps_rows):
    assert len(steps) == 4, f"Part {p_idx+1} must have 4 steps"
    for s_idx, rows in enumerate(steps):
        assert len(rows) == 2, f"Part {p_idx+1} step {s_idx+1} must have 2 rows"
        for r_idx, row in enumerate(rows):
            assert len(row) == 3, f"Part {p_idx+1} step {s_idx+1} row {r_idx+1} must have 3 cells"
            for c_idx, cell in enumerate(row):
                assert not any(ch.isdigit() for ch in cell), f"Part {p_idx+1} step {s_idx+1} cell {r_idx+1},{c_idx+1} has digits: {cell}"

# Build visual entries
visual_entries = []
step_keys = ["say1", "say2", "example", "tryIt"]

for p_idx in range(5):
    p_num = p_idx + 1
    p_title = parts_data[p_idx]["title"]
    v_title = titles[p_idx]
    v_cols = columns_list[p_idx]
    
    steps = []
    for s_idx, key in enumerate(step_keys):
        cap = captions_data[p_idx][key]
        rows = steps_rows[p_idx][s_idx]
        steps.append({
            "at": key,
            "caption": cap,
            "rows": rows
        })
        
    spec = {
        "template": "table",
        "title": v_title,
        "columns": v_cols,
        "steps": steps
    }
    
    visual_entries.append({
        "partTitle": p_title,
        "codeHash": code_hash,
        "spec": spec
    })

visual_envelope = {
    "schemaVersion": "2.0.0",
    "course": "prompt-py",
    "day": 52,
    "prefix": "prompt-py",
    "entries": visual_entries
}

# Build parts list for lesson
lesson_parts = []
total_words = 0
for idx, p in enumerate(parts_data):
    w_cnt = len(" ".join(p["say"]).split())
    total_words += w_cnt
    print(f"Part {idx+1}: {w_cnt} words")

for idx, p in enumerate(parts_data):
    w_cnt = len(" ".join(p["say"]).split())
    assert w_cnt >= 600, f"Part {idx+1} word count too low: {w_cnt}"
    lesson_parts.append({
        "title": p["title"],
        "say": p["say"],
        "example": p["example"],
        "code": code_snippet,
        "output": output_snippet,
        "tryIt": p["tryIt"],
        "check": p["check"]
    })

print(f"Total words: {total_words}")
assert total_words >= 3100, f"Total words too low: {total_words}"

lesson = {
    "id": "prompt-py-52",
    "day": 52,
    "course": "prompt-py",
    "title": "Input Validation & Defensive Filtering: NeMo Guardrails, Llama Guard, Perplexity Classifiers & Semantic Pre-Flight Sanitization",
    "minutes": 38,
    "parts": lesson_parts,
    "projectStep": {
        "title": "Engineer Multi-Tier Defensive Input Filtering Engine",
        "steps": [
            "Construct a sliding-window token perplexity filter intercepting universal adversarial suffixes.",
            "Deploy a quantized Llama Guard classifier evaluating prompts against the fourteen-point safety taxonomy.",
            "Implement a NeMo Guardrails policy in Colang defining topical boundaries and tool execution rules.",
            "Deploy an asynchronous Python input validation pipeline uniting statistical and neural filters.",
            "Integrate OpenTelemetry telemetry and cryptographic audit logging for all filtered prompt requests."
        ]
    },
    "summary": [
        "Pre-flight input guardrails decouple safety enforcement from foundation model attention streams.",
        "Llama Guard categorizes user prompts and model completions against standardized MLCommons hazard policies.",
        "NeMo Guardrails enforces programmable dialogue flows and tool execution constraints using Colang.",
        "Perplexity classifiers detect statistical anomalies characteristic of gradient-optimized adversarial suffixes.",
        "Multi-layer defensive input filtering engines deflect over ninety-nine percent of adversarial attacks."
    ]
}

# Write lesson JSON and visual envelope JSON
with open("C:/Users/Admin/Desktop/projects/Present-Career-os-platform/scripts/branch_c/prompt_day52_lesson.json", "w", encoding="utf-8") as f:
    json.dump(lesson, f, indent=2)

with open("C:/Users/Admin/Desktop/projects/Present-Career-os-platform/src/lib/data/lessonVisuals/prompt-py/day-52.json", "w", encoding="utf-8") as f:
    json.dump(visual_envelope, f, indent=2)

print("Generated Day 52 lesson JSON and Visual Envelope successfully!")
