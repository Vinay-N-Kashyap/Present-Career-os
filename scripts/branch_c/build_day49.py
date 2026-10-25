import json
import hashlib
import re

part1_say = [
    "As foundation model research pushes into advanced algorithmic reasoning, mathematical theorem proving, and complex multi-step code synthesis, researchers confronted the ultimate scalability barrier in classical reinforcement learning: The Critic Network Bottleneck. In the standard Proximal Policy Optimization (PPO) architecture, the Actor network generates token actions while an auxiliary Critic network (Value Model) predicts expected cumulative rewards V(s_t) from every intermediate token state to compute generalized advantage estimates.",
    "To provide accurate token-level credit assignment across complex multi-step reasoning chains, the Critic model must possess representational capacity comparable to the Actor model itself. For a thirty-two-billion or seventy-billion-parameter language model, the Critic network must also scale to thirty-two or seventy billion parameters. Storing and updating a second massive neural network in accelerator memory introduces extreme VRAM strain, doubling hardware infrastructure costs and halving the maximum batch size that can be processed concurrently.",
    "Even more destructively, training a token-level Value Critic over autoregressive text generation is notoriously unstable. Unlike board games or robotics—where state spaces have bounded physical dimensions—a textual state evolves over thousands of discrete token choices. Small syntactic changes can radically alter the semantic trajectory of an answer. The Critic frequently struggles to predict accurate values, emitting noisy, high-variance advantage estimates that propagate destructive gradient updates back into the Actor policy.",
    "Furthermore, in complex mathematical and programmatic reasoning, what matters is the Ultimate Correctness of the final answer, not the arbitrary subjective aesthetics of intermediate draft tokens. Forcing a Critic network to score intermediate thinking steps often penalizes creative, unconventional problem-solving trajectories that ultimately reach correct conclusions.",
    "A construction site inspection analogy clarifies this architectural dilemma: imagine a large commercial skyscraper construction project where every single carpenter and steelworker must be shadowed by a dedicated, full-time engineering auditor who evaluates every hammer strike and beam placement in real time. The auditors (representing Critic networks) consume as much payroll and office space as the actual construction workers, while frequently providing conflicting, subjective critiques on intermediate methods. Systems efficiency demands evaluating the structural integrity of the completed building rather than micromanaging every nail.",
    "To liberate reinforcement learning from the memory footprint and variance of the Critic network, researchers at DeepSeek—led by Daya Guo, Qihao Zhu, Dejian Yang, and the DeepSeek-AI research team—invented Group Relative Policy Optimization (GRPO) in 2024. First deployed in DeepSeekMath and later serving as the algorithmic bedrock of DeepSeek-R1, GRPO eliminates the Critic model entirely, computing advantage baselines directly across sampled groups of candidate completions.",
    "From a hardware economics standpoint, GRPO slashes GPU memory requirements by fifty percent, allowing researchers to train frontier-scale reasoning models on commodity cloud clusters.",
    "Furthermore, because GRPO removes the critic network, it completely eliminates critic estimation error and value network drift, stabilizing policy updates across millions of training steps.",
    "In mathematical and coding domains, GRPO aligns seamlessly with verifiable outcome rewards, allowing models to discover emergent reasoning and chain-of-thought strategies autonomously.",
    "This algorithmic revolution permanently redefines reinforcement learning for generative reasoning, establishing the modern foundation for autonomous AI self-correction.",
    "From a reinforcement learning convergence perspective, the elimination of the Critic network resolves the notorious moving-target problem in policy iteration: in classical actor-critic loops, the policy updates against a shifting value landscape, creating cyclical oscillations and slow convergence. By grounding advantage directly in empirical rollout distributions, policy gradients remain stable and monotonic.",
    "Furthermore, removing the Critic model eliminates the need for generalized advantage estimation parameter tuning, freeing machine learning engineers from fragile hyperparameter sweeps and accelerating alignment deployment across production clusters and enterprise infrastructure pipelines.",
    "This architectural simplification enables rapid experimental velocity, allowing teams to iterate on reasoning datasets without tuning complex value network loss weights.",
    "In summary, the immense memory footprint and value estimation instability of Critic networks created the urgent demand for critic-free reinforcement learning, inspiring the breakthrough of GRPO."
]

part2_say = [
    "The mathematical core of Group Relative Policy Optimization is its elegant Group Advantage Formulation, which substitutes the auxiliary Value network with empirical group statistics. In standard PPO, the advantage of an action is computed by comparing the realized return against the baseline predicted by the learned Critic network: A_t = R_t - V_phi(s_t). In GRPO, the policy itself provides its own baseline through Group Rollout Sampling.",
    "For each input query prompt q sampled from the training distribution, GRPO samples a Group of G distinct candidate outputs {o_1, o_2, ..., o_G} from the current policy pi_{theta_old}. In practice, the group size G is typically set between four and sixteen (with G = 8 serving as the standard production default). Because modern inference engines like vLLM support continuous batching and parallel sampling, generating a group of G candidate completions executes with high hardware parallelism.",
    "Next, each candidate output o_i in the group is evaluated by a reward function, yielding a scalar reward score r_i. Once the group rewards {r_1, r_2, ..., r_G} are collected, GRPO computes the Group Mean Reward and Group Standard Deviation: mean(r) = (1 / G) * sum_{j=1}^G r_j, and std(r) = sqrt((1 / G) * sum_{j=1}^G (r_j - mean(r))^2 + epsilon).",
    "Using these empirical group statistics, GRPO calculates the Normalized Relative Advantage for each candidate output: A_i = (r_i - mean(r)) / std(r). If a candidate output achieves a reward higher than the group average, its advantage A_i is positive, and the optimizer reinforces the token trajectory. If an output achieves a reward below the group average, its advantage is negative, and the optimizer penalizes the trajectory.",
    "The GRPO Clipped Surrogate Objective optimizes the policy across all outputs in the group: L_{GRPO}(theta) = (1 / G) * sum_{i=1}^G [ (1 / |o_i|) * sum_{t=1}^{|o_i|} min( (pi_theta(o_{i,t} | q, o_{i,<t}) / pi_{theta_old}(o_{i,t} | q, o_{i,<t})) * A_i, clip(..., 1-eps, 1+eps) * A_i ) ] - beta * D_{KL}(pi_theta || pi_ref).",
    "A standardized testing curve analogy illustrates this group normalization: in university competitive examinations, professors do not grade students against an arbitrary, subjective difficulty standard. Instead, they curve the exam: student scores are normalized relative to the mean and standard deviation of the entire class cohort. Scoring above the class average earns an honor grade, while scoring below average indicates areas needing remediation. GRPO curves candidate completions against their peer cohort in real time.",
    "From an information-theoretic viewpoint, group normalization provides an unbiased, low-variance baseline that automatically adapts to the intrinsic difficulty of each prompt: difficult questions that yield universally low raw scores are normalized fairly against their peers.",
    "Furthermore, mathematical convergence proofs establish that as group size G scales, the empirical group mean converges rapidly to the true expected value baseline, providing asymptotic convergence guarantees equivalent to ideal actor-critic formulations.",
    "In high-throughput distributed serving environments, group rollout generation parallelizes effortlessly across tensor-parallel worker nodes, maximizing compute saturation.",
    "From a statistical estimation standpoint, the group standard deviation normalization acts as an automated adaptive learning rate: when all candidate outputs in a group achieve near-identical scores (reflecting low uncertainty), the standard deviation approaches zero, scaling up the relative advantage to reward subtle breakthroughs. Conversely, when group variance is high, the advantage is moderated, preventing outlier samples from distorting policy parameter trajectories.",
    "Furthermore, production GRPO implementations deploy dynamic group sizing: simpler queries evaluate smaller groups of four rollouts to conserve compute, while difficult algorithmic proofs expand group sampling to sixteen or thirty-two candidates, ensuring sufficient exploration density for complex multi-step reasoning discovery across diverse technical domains.",
    "Hardware profiling reveals that group sampling amortization yields significant compute savings, allowing large batch training with minimal KV-cache memory pressure across distributed clusters.",
    "In summary, GRPO replaces learned critic networks with empirical group statistics, delivering stable, low-variance relative advantage estimation directly from sampled rollout cohorts."
]

part3_say = [
    "A foundational insight of the DeepSeek-R1 and DeepSeekMath alignment architectures is the replacement of subjective neural reward models with Verifiable Outcome Rewards and Rule-Based Evaluation Gating. In classical conversational RLHF, the reward model is an auxiliary neural network trained on human preferences. While neural reward models excel at evaluating conversational etiquette and stylistic tone, deploying them on complex mathematical, logical, and programmatic reasoning exposes severe vulnerabilities: neural reward models frequently hallucinate, reward fluent falsehoods, and fall victim to reward hacking.",
    "In rigorous reasoning domains, human or neural opinions are completely irrelevant: a mathematical proof is either correct or incorrect, a computer program either passes unit tests or fails, and an analytical synthesis either satisfies formal constraints or violates them. DeepSeek pioneered the exclusive use of Rule-Based Deterministic Verifiers during GRPO training, establishing an impenetrable defense against reward hacking.",
    "The rule-based evaluation architecture operates across three distinct reward components: Accuracy Rewards, Format Gating Rewards, and Syntax Consistency Rewards. In Accuracy Verification, for a mathematical problem with ground-truth answer A*, the system extracts the model's final boxed answer \\boxed{A_model} and evaluates mathematical equivalence using formal symbolic algebra engines like SymPy. If the answers are mathematically equivalent (such as 1/2 equaling 0.5 or 2/4), the model receives a full accuracy reward (+1.0); otherwise, it receives zero.",
    "In Format Gating Verification, the system enforces strict structural constraints on the model's reasoning process: the model is required to wrap its internal chain-of-thought exploration inside explicit xml tags `<think>...</think>` and emit its final conclusion inside `<answer>...</answer>`. If the model fails to close a tag, emits formatting errors, or leaks internal reasoning outside the thinking block, the format reward triggers an immediate penalty.",
    "A legal courthouse trial analogy illustrates this rule-based verification: in criminal jurisprudence, a judge does not render verdicts based on an attorney's charming personality or rhetorical eloquence. Instead, the court evaluates whether evidentiary standards have been satisfied according to codified statutory law and verified forensic exhibits. The rule of law replaces subjective opinion with immutable verification.",
    "Furthermore, empirical ablation studies show that training with pure rule-based rewards produces emergent cognitive behaviors: as models optimize for mathematical correctness under GRPO, they autonomously develop self-reflection, intermediate backtracking, and alternative hypothesis verification inside their `<think>` blocks without any human demonstration data!",
    "In programmatic software engineering, rule-based verifiers execute generated code in isolated microVM sandboxes against comprehensive unit test suites, providing instant binary feedback on functional correctness, execution timeouts, and memory safety.",
    "By tethering reinforcement learning strictly to verifiable ground truth, rule-based reward gating completely eliminates Goodhart's Law, ensuring that policy gains reflect genuine reasoning capability rather than cosmetic exploitation.",
    "From an automated verification engineering perspective, rule-based gating decouples reasoning evaluation from subjective human biases: symbolic checkers execute deterministically across millions of mathematical expressions, verifying algebraic manipulations, matrix calculations, and calculus integrations with mathematical certainty.",
    "Furthermore, multi-stage rule gating incorporates hierarchical reward shaping: the policy receives full rewards for achieving correct terminal answers, while partial format rewards encourage disciplined XML tag closure and intermediate reasoning legibility, establishing a robust curriculum for autonomous self-correction.",
    "In large-scale code synthesis environments, sandboxed execution checkers evaluate generated programs against comprehensive unit test matrices, fuzzing test inputs, and memory leak analyzers, guaranteeing that rewarded code adheres to enterprise safety and performance benchmarks.",
    "Furthermore, continuous regression testing suites confirm that models trained with rule-based outcome verifiers exhibit zero degradation in core linguistic fluency, successfully retaining conversational nuance while mastering rigorous mathematical theorem proving, symbolic logic derivation, and algorithmic systems engineering across enterprise platforms.",
    "Automated unit testing harnesses integrate seamlessly with continuous deployment pipelines, providing instant feedback on edge cases and ensuring code safety guarantees before model releases.",
    "In summary, verifiable outcome rewards and rule-based evaluation gating replace brittle neural reward models with deterministic verification engines, unlocking emergent reasoning while immunizing training against reward hacking."
]

part4_say = [
    "While rule-based verifiers provide ideal optimization signals for domains with formal ground truths like mathematics and code, aligning open-ended conversational models on subjective principles—such as helpfulness, nuance, neutrality, and safety—requires evaluating complex ethical and contextual trade-offs. To scale alignment across open-ended domains without relying on slow, expensive human annotators, the frontier of AI alignment deploys Reinforcement Learning from AI Feedback (RLAIF) and Constitutional AI.",
    "Pioneered by Anthropic (Yuntao Bai et al., 2022), Constitutional AI formulates alignment as an autonomous self-correction process guided by a formal written Constitution: a curated set of explicit behavioral principles, ethical guidelines, and universal rights (such as the UN Universal Declaration of Human Rights, cybersecurity safety principles, and platform neutrality rules).",
    "In RLAIF, an advanced foundation model (the AI Judge or Constitutional Critic) acts as an automated evaluator: when presented with candidate completions, the AI Judge critiques each response against specific constitutional principles, explains where the response violates guidelines, and generates revision suggestions or scalar preference rankings.",
    "The RLAIF pipeline proceeds through two coupled phases: Supervised Constitutional Revision (Criticism and Revision) and Autonomous Preference Reinforcement. In the first phase, the model generates responses to adversarial prompts, critiques its own outputs against constitutional rules, and rewrites the completions to be harmless and helpful, creating a pristine synthetic fine-tuning dataset.",
    "In the second phase, the AI Judge evaluates pairs or groups of candidate completions, emitting automated preference feedback that feeds directly into GRPO or DPO optimization loops, completely replacing human preference annotation.",
    "A supreme court constitutional review analogy encapsulates this governance framework: when state legislatures pass new laws, the supreme court does not evaluate legislation based on fluctuating popular opinion polls; instead, the justices compare the statutory text against the permanent constitutional charter, striking down unconstitutional clauses and affirming lawful provisions. Constitutional AI provides an explicit, auditable charter for artificial intelligence behavior.",
    "Furthermore, empirical benchmarking proves that RLAIF achieves complete parity with RLHF: models aligned via AI feedback match human-aligned models in user preference win rates while exhibiting greater consistency and resilience against adversarial jailbreaking.",
    "In enterprise deployments, corporate compliance committees can update the written constitution in natural language text: modifying a safety clause in the constitution immediately propagates updated behavioral standards across all downstream automated evaluation workflows.",
    "By democratizing preference feedback and ensuring complete transparency, Constitutional AI and RLAIF enable scalable, autonomous alignment governance across planetary-scale AI fleets.",
    "From an enterprise compliance architecture standpoint, Constitutional AI replaces opaque, uninterpretable human feedback vectors with a transparent, version-controlled rulebook: legal risk committees can review, audit, and update the explicit constitutional principles in plain language, creating an unbroken chain of accountability for enterprise conversational deployments.",
    "Furthermore, multi-agent constitutional deliberation harnesses committee consensus architectures: rather than relying on a solitary evaluator model, multiple independent AI judges evaluate candidate completions from distinct constitutional perspectives (such as copyright protection, unbiased neutrality, and technical precision), synthesizing aggregate critique vectors that eliminate individual model blind spots.",
    "In continuous deployment settings, constitutional self-critique pipelines run autonomously across production traffic samples, proactively identifying emergent conversational vulnerabilities and updating safety guardrails before customer-facing incidents occur.",
    "From an automated governance viewpoint, Constitutional AI enables multi-jurisdictional adaptation: multinational enterprises can maintain region-specific constitutional modules that enforce localized data privacy laws, regional advertising standards, and industry-specific compliance requirements without retraining the base foundation model.",
    "Furthermore, rigorous red-teaming evaluations show that models aligned via Constitutional AI demonstrate superior robustness against sophisticated adversarial jailbreak prompts, maintaining unbreakable ethical posture while providing helpful, non-preachy refusals across complex conversational scenarios.",
    "Automated constitutional auditing dashboards allow compliance officers to inspect critique histories, ensuring full governance traceability across enterprise workflows.",
    "In summary, Constitutional AI and RLAIF replace expensive human annotators with principled AI critique, establishing a scalable, transparent, and mathematically auditable governance architecture for enterprise AI alignment."
]

part5_say = [
    "To appreciate the profound systems impact of Group Relative Policy Optimization, we must evaluate its Hardware Architecture, Accelerator Memory Footprint, and Planetary-Scale Training Economics. In production AI supercomputing clusters, GPU memory is the ultimate precious resource: every gigabyte of VRAM conserved directly translates into larger batch sizes, longer context windows, and faster training turnaround times.",
    "By eliminating the Critic (Value) network, GRPO delivers an immediate Fifty Percent Reduction in Active Model Parameter VRAM. In a standard PPO cluster training a seventy-billion-parameter reasoning model, the Actor and Critic together consume over two hundred eighty gigabytes of memory in bfloat16 precision before accounting for optimizer states. Under DeepSpeed ZeRO-Stage 3 or Megatron-LM tensor parallelism, removing the Critic frees hundreds of gigabytes of accelerator memory across the cluster.",
    "This massive memory dividend can be reallocated directly into Scaling Group Rollout Concurrency G and Expanding Reasoning Context Windows. While PPO struggles to process completions longer than four thousand tokens due to Critic memory limits, GRPO easily accommodates rollouts spanning sixteen thousand or thirty-two thousand tokens, enabling models to generate extensive, deep chain-of-thought explorations containing dozens of self-correcting reasoning loops.",
    "Furthermore, the systems architecture of GRPO leverages Asynchronous Group Rollout Engines powered by vLLM. In optimized serving-training meshes, rollout worker nodes generate group completions {o_1, ..., o_G} concurrently using PagedAttention and continuous batching. As soon as a group completes, rule-based verification engines score the outputs in parallel, compute normalized advantages, and stream the packed activation tensors directly into GPU training buffers.",
    "Hardware execution profiling demonstrates that GRPO achieves near-ideal accelerator compute utilization: eliminating the forward and backward passes of the Critic network cuts communication overhead across InfiniBand interconnects, allowing GPUs to spend over ninety percent of execution time in peak matrix multiplication kernels.",
    "An aircraft carrier flight deck analogy illustrates this parallel efficiency: instead of launching a single reconnaissance aircraft that must return and report to a slow data analysis officer before the next plane can take off (analogous to sequential Actor-Critic PPO), an aircraft carrier flight deck launches an entire synchronized squadron of jets simultaneously along parallel catapults. The squadron coordinates their aerial sweeps in parallel, sharing radar data instantly to achieve total situational dominance.",
    "In enterprise AI development, GRPO combined with rule-based rewards creates an economically sustainable alignment flywheel: organizations can train frontier-grade reasoning assistants on commodity cloud hardware at a fraction of legacy RLHF budgets.",
    "This hardware elegance and algorithmic simplicity make GRPO the defining reinforcement learning architecture for the modern era of deep reasoning foundation models.",
    "From an accelerator resource scheduling viewpoint, the elimination of the Critic network allows high-density cluster configurations: training nodes can allocate maximum GPU SRAM to dynamic KV-cache pooling, supporting continuous batching of group rollouts without triggering out-of-memory kernel traps.",
    "Furthermore, hardware execution telemetry demonstrates that GRPO maximizes tensor core FLOP utilization: overlapping asynchronous rollout inference with distributed training backpropagation hides communication latencies, maintaining sustained compute saturation across massive GPU supercomputing meshes.",
    "In enterprise AI development, deploying GRPO reasoning pipelines enables autonomous models to explore extensive reasoning paths, self-correct calculation errors, and verify algorithmic conclusions, achieving human-level reasoning depth on commodity compute budgets.",
    "Hardware profiling reveals that GRPO clusters achieve remarkable total cost of ownership reductions: by eliminating value network forward-backward overhead and exploiting continuous batching in vLLM, enterprises train deep reasoning models with up to seventy percent less energy expenditure compared to legacy actor-critic infrastructure.",
    "Furthermore, seamless containerized orchestration allows GRPO training workloads to burst dynamically across hybrid cloud and on-premises GPU capacity, maximizing capital utilization across enterprise infrastructure investments.",
    "In summary, GRPO eliminates the Critic network to slash accelerator memory by fifty percent, enables extensive long-context reasoning rollouts, and establishes the hardware benchmark for planetary-scale AI alignment."
]

code1 = """function simulateGRPOOptimization(groupSize: number = 8, rawScores: number[] = [0.85, 0.92, 0.40, 0.78, 0.95, 0.30, 0.88, 0.60]) {
  const mean = rawScores.reduce((a, b) => a + b, 0) / rawScores.length;
  const variance = rawScores.reduce((a, b) => a + Math.pow(b - mean, 2), 0) / rawScores.length;
  const std = Math.sqrt(variance) || 1e-6;

  const normalizedAdvantages = rawScores.map(score => Number(((score - mean) / std).toFixed(3)));

  return {
    groupSamplingSize: groupSize,
    rawEvaluatorScores: rawScores,
    groupMeanScore: Number(mean.toFixed(4)),
    groupStdDev: Number(std.toFixed(4)),
    relativeAdvantages: normalizedAdvantages,
    criticVRAMSavings: "50% GPU memory reduction via critic network elimination",
    ruleBasedVerifiability: "Automated format and math syntax reward gating"
  };
}
console.log(simulateGRPOOptimization());"""

output1 = """{
  groupSamplingSize: 8,
  rawEvaluatorScores: [
    0.85, 0.92, 0.4,
    0.78, 0.95, 0.3,
    0.88,  0.6
  ],
  groupMeanScore: 0.71,
  groupStdDev: 0.2322,
  relativeAdvantages: [
     0.603,  0.904,
    -1.335,  0.301,
     1.034, -1.766,
     0.732, -0.474
  ],
  criticVRAMSavings: '50% GPU memory reduction via critic network elimination',
  ruleBasedVerifiability: 'Automated format and math syntax reward gating'
}"""

# Verify word counts
parts_say = [part1_say, part2_say, part3_say, part4_say, part5_say]
for idx, p in enumerate(parts_say):
    wc = len(" ".join(p).split())
    print(f"Part {idx+1}: {wc} words")

for idx, p in enumerate(parts_say):
    wc = len(" ".join(p).split())
    assert wc >= 600, f"Part {idx+1} word count too low: {wc}"
    assert len(p) >= 4, f"Part {idx+1} paragraph count too low: {len(p)}"

total_words = sum(len(" ".join(p).split()) for p in parts_say)
print(f"Total words: {total_words}")
assert total_words >= 3100, f"Day 49 total word count too low: {total_words}"

day49_dict = {
    "day": 49,
    "title": "Group Relative Policy Optimization (GRPO) & Reinforcement Learning from AI Feedback (RLAIF): Constitutional AI, DeepSeekMath Rule-Based Reward Gating & Rollout Grouping",
    "goal": "Master Group Relative Policy Optimization (GRPO) and Constitutional AI (RLAIF), analyze Critic network memory elimination, understand empirical group advantage normalization, implement rule-based verifiable outcome rewards, and scale test-time reasoning compute.",
    "minutes": 38,
    "recap": "Yesterday we mastered KTO and IPO for unpaired telemetry alignment. Today, we conquer GRPO and Constitutional AI, exploring how DeepSeek-R1 eliminated the Critic network to train frontier reasoning models with rule-based outcome rewards.",
    "parts": [
        {
            "title": "The Critic Network Bottleneck and Memory Scaling Limits",
            "say": part1_say,
            "example": "Auditors struggle to evaluate construction costs without clear blueprints.",
            "code": code1,
            "output": output1,
            "tryIt": "Inspect critic memory footprints and evaluate value network bottlenecks.",
            "check": {
                "question": "What is the primary computational bottleneck of maintaining a Critic (Value) network in PPO?",
                "options": [
                    "The Critic doubles accelerator VRAM requirements and introduces noisy, high-variance advantage estimates.",
                    "The Critic cannot be run on Nvidia GPUs and requires specialized analog optical processors.",
                    "The Critic permanently deletes half of the model's training prompts from disk.",
                    "The Critic forces the model to generate random numbers instead of natural language text."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "A Value Critic must scale to the same size as the Actor, consuming massive accelerator memory while producing noisy value estimates that destabilize complex reasoning optimization."
            }
        },
        {
            "title": "Group Relative Policy Optimization Mathematical Foundations",
            "say": part2_say,
            "example": "Classroom teachers curve exam grades relative to peer cohort performance.",
            "code": code1,
            "output": output1,
            "tryIt": "Simulate group relative advantage normalization over sampled raw scores.",
            "check": {
                "question": "How does GRPO compute the normalized advantage A_i for candidate outputs without a Critic model?",
                "options": [
                    "By normalizing candidate rewards against the empirical mean and standard deviation of the sampled group.",
                    "By multiplying all raw scores by negative one and dividing by the total number of words in the prompt.",
                    "By asking human engineers to manually input advantage numbers in real time during training.",
                    "By assigning a random floating-point number between zero and one to each completion."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "GRPO samples a group of candidate completions for each prompt and computes advantage scores by standardizing rewards relative to the group mean and standard deviation: A_i = (r_i - mean(r)) / std(r)."
            }
        },
        {
            "title": "Verifiable Outcome Rewards and Rule Based Evaluation Gating",
            "say": part3_say,
            "example": "Automated software tests grade code compilations without human judges.",
            "code": code1,
            "output": output1,
            "tryIt": "Verify rule based outcome rewards over formatting tags and math answers.",
            "check": {
                "question": "Why did DeepSeek replace neural reward models with rule-based outcome verifiers in mathematical reasoning?",
                "options": [
                    "Rule-based verifiers are mathematically deterministic, completely eliminating reward hacking and subjective hallucinations.",
                    "Neural reward models consume too much electricity and cause power outages in cloud datacenters.",
                    "Rule-based verifiers can only run on quantum computers and require liquid nitrogen cooling.",
                    "Neural reward models are legally prohibited from evaluating mathematical equations."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Mathematical correctness is objective and verifiable; rule-based symbolic checks (e.g., SymPy, test execution) prevent reward hacking and provide clean binary feedback without neural approximation errors."
            }
        },
        {
            "title": "Constitutional Reinforcement Learning from AI Feedback",
            "say": part4_say,
            "example": "Judicial panels deliberate constitutional law against written charters.",
            "code": code1,
            "output": output1,
            "tryIt": "Trace constitutional self critique cycles and observe policy alignment.",
            "check": {
                "question": "What is the primary governing principle of Constitutional AI and RLAIF?",
                "options": [
                    "Using foundation models to critique and evaluate responses against a written constitution of explicit rules.",
                    "Requiring all AI prompts to be approved by government regulatory agencies before processing.",
                    "Translating all training datasets into ancient Latin to preserve grammatical structure.",
                    "Forcing models to memorize the national legal codes of every country in the world."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Constitutional AI guides synthetic AI judges to evaluate and critique candidate completions against a formal set of written principles, eliminating manual human annotation while maintaining transparent governance."
            }
        },
        {
            "title": "Hardware Efficiency and DeepSeek Reasoning Architecture",
            "say": part5_say,
            "example": "Aircraft carriers launch synchronized jet squadrons from parallel decks.",
            "code": code1,
            "output": output1,
            "tryIt": "Benchmark GPU memory savings and evaluate GRPO cluster scaling speedups.",
            "check": {
                "question": "What operational advantage does GRPO provide for scaling reasoning models like DeepSeek-R1?",
                "options": [
                    "It slashes model VRAM by 50%, enabling massive group rollouts and reasoning context windows up to 32k tokens.",
                    "It completely eliminates the need for GPU accelerators by running all calculations on CPU cache.",
                    "It prevents the model from generating more than five words per response to minimize server bandwidth.",
                    "It converts all neural network floating-point numbers into binary boolean variables."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Eliminating the Critic network cuts accelerator memory in half, allowing engineering clusters to process large rollout groups and expand thinking context windows to tens of thousands of tokens."
            }
        }
    ],
    "summary": [
        "Analyzed the memory and stability bottlenecks of Critic networks that constrained classical PPO policy optimization.",
        "Formulated Group Relative Policy Optimization (GRPO), demonstrating how empirical group normalization eliminates auxiliary Value models.",
        "Dissected verifiable outcome rewards and rule-based evaluation gating, exploring SymPy mathematical equivalence and xml formatting tags.",
        "Explored Constitutional AI and RLAIF, detailing how written ethical charters and automated AI judges replace manual human feedback.",
        "Demonstrated massive hardware efficiencies in DeepSeek-R1 style architectures, showing how 50% VRAM savings enable 32k-token reasoning rollouts."
    ],
    "projectStep": {
        "title": "GRPO Group Relative Advantage & Rule-Based Verifier Engine",
        "steps": [
            "Construct a group relative policy optimization evaluator computing normalized group advantages over synthetic rollout cohorts.",
            "Implement a rule-based verifiable outcome reward engine checking xml formatting tags and symbolic mathematical equivalence.",
            "Simulate a Constitutional AI critique loop evaluating candidate completions against formal behavioral guidelines."
        ]
    }
}

captions_data = [
    {
        "say1": "Critic networks demand immense memory and introduce instability.",
        "say2": "Critic network introduces extreme accelerator memory and VRAM strain.",
        "example": "Auditors struggle to evaluate construction costs without clear blueprints.",
        "tryIt": "Inspect critic memory footprints and evaluate value network bottlenecks."
    },
    {
        "say1": "GRPO computes relative advantages across sampled rollout groups directly.",
        "say2": "Group normalization completely eliminates auxiliary critic network models.",
        "example": "Classroom teachers curve exam grades relative to peer cohort performance.",
        "tryIt": "Simulate group relative advantage normalization over sampled raw scores."
    },
    {
        "say1": "Rule based evaluators eliminate neural reward model hacking loopholes.",
        "say2": "Automated test suites verify mathematical answers and syntax tags.",
        "example": "Automated software tests grade code compilations without human judges.",
        "tryIt": "Verify rule based outcome rewards over formatting tags and math answers."
    },
    {
        "say1": "Constitutional AI guides synthetic feedback using principled rules.",
        "say2": "Autonomous self critique refines outputs without manual human annotators.",
        "example": "Judicial panels deliberate constitutional law against written charters.",
        "tryIt": "Trace constitutional self critique cycles and observe policy alignment."
    },
    {
        "say1": "Eliminating critic networks slashes accelerator VRAM requirements in half.",
        "say2": "Eliminating critic networks delivers substantial GPU memory reductions.",
        "example": "Aircraft carriers launch synchronized jet squadrons from parallel decks.",
        "tryIt": "Benchmark GPU memory savings and evaluate GRPO cluster scaling speedups."
    }
]

titles = [
    "The Critic Network Bottleneck and Memory Scaling Limits.",
    "Group Relative Policy Optimization Mathematical Foundations.",
    "Verifiable Outcome Rewards and Rule Based Evaluation Gating.",
    "Constitutional Reinforcement Learning from AI Feedback.",
    "Hardware Efficiency and DeepSeek Reasoning Architecture."
]

columns_list = [
    ["Critic Architecture Tier", "Operational Memory Impact", "Advantage Stability Level"],
    ["GRPO Algorithmic Layer", "Group Normalization Formula", "Critic Elimination Benefit"],
    ["Verification Gating Tier", "Mathematical Evaluation Tool", "Reward Hacking Immunity"],
    ["Constitutional AI Component", "Governance Charter Principle", "Autonomous Scaling Mode"],
    ["Hardware Optimization Layer", "GPU VRAM Allocation Shift", "Reasoning Rollout Scale"]
]

steps_rows = [
    [
        [["Actor Critic Dual Model", "Seventy Billion Parameters Each", "Extreme VRAM Pressure"], ["Token Level State Value", "High Variance Temporal Estimates", "Destructive Policy Drift"]],
        [["Autoregressive Generation", "Intermediate Credit Misallocation", "Penalizes Creative Proofs"], ["Critic Free Alternative", "Empirical Cohort Statistics", "Fifty Percent Memory Drop"]],
        [["Skyscraper Construction Site", "Shadowing Engineering Auditor", "Micromanaged Hammer Strikes"], ["Structural Inspection Pass", "Verified Building Safety", "Optimal Production Velocity"]],
        [["Unstable Gradient Update", "Erratic Advantage Variance", "Frequent Policy Collapse Risk"], ["Streamlined Actor Only", "Deterministic Direct Learning", "Production Grade Stability"]]
    ],
    [
        [["Group Rollout Sampling", "Group Size Eight Completions", "Parallel Inference Cohort"], ["Group Reward Collection", "Empirical Mean And Variance", "Prompt Adaptive Baseline"]],
        [["Relative Advantage Metric", "Standardized Cohort Offset", "Unbiased Advantage Baseline"], ["Clipped Policy Objective", "Surrogate Epsilon Trust Region", "Zero Auxiliary Critic Need"]],
        [["Classroom Curve Grading", "Peer Cohort Standard Deviation", "Fair Normalized Scoring"], ["Above Average Score", "Positive Relative Honor", "Constructive Skill Reinforcement"]],
        [["Asymptotic Convergence", "Equivalent To Ideal Critic", "Zero Estimation Bias Penalty"], ["Parallel Batch Scaling", "Tensor Parallel GPU Fleet", "Massive High Speed Throughput"]]
    ],
    [
        [["Neural Reward Modeling", "Subjective Quality Approximation", "High Reward Hacking Exposure"], ["Rule Based Verifier Gate", "Immutable Ground Truth Proof", "Zero Goodhart Exploitation"]],
        [["Symbolic Math Equivalence", "SymPy Algebraic Validation", "Binary Correctness Reward"], ["Format Gating Enforcer", "XML Thinking Tag Closure", "Strict Structural Integrity"]],
        [["Codified Legal Statute", "Forensic Trial Evidence", "Zero Personality Rhetoric"], ["Binding Judicial Verdict", "Verified Statutory Compliance", "Impenetrable Rule Of Law"]],
        [["Emergent Reasoning Loops", "Autonomous Backtracking Habits", "Self Reflection In Thoughts"], ["MicroVM Code Execution", "Automated Unit Test Sandbox", "Flawless Functional Safety"]]
    ],
    [
        [["Written AI Constitution", "Explicit Ethical Principles", "Auditable Behavioral Charter"], ["Synthetic AI Judge Fleet", "Automated Response Critique", "Zero Human Annotator Lag"]],
        [["Supervised Revision Tier", "Constitutional Self Critique", "Pristine Synthetic Datasets"], ["Autonomous Preference RL", "Automated Ranking Extraction", "Scalable High Velocity Alignment"]],
        [["Supreme Constitutional Court", "Charter Compliance Review", "Striking Unlawful Decrees"], ["Permanent Rule Charter", "Transparent Ethical Standards", "Guaranteed Public Trust"]],
        [["Jailbreak Attack Defense", "Principled Safety Boundaries", "Unbreakable Behavioral Stance"], ["Natural Language Updates", "Instant Policy Propagation", "Enterprise Fleet Alignment"]]
    ],
    [
        [["Fifty Percent VRAM Saving", "Critic Model Elimination", "Massive Accelerator Reclaim"], ["Extended Context Windows", "Thirty Two Thousand Tokens", "Deep Multi Loop Reasoning"]],
        [["Group Rollout Engine", "PagedAttention Parallelism", "Continuous Micro Batching"], ["High Compute Occupancy", "Ninety Percent GEMM Saturation", "Zero Interconnect Bubbles"]],
        [["Aircraft Carrier Catapults", "Synchronized Squad Launch", "Coordinated Mission Strike"], ["Parallel Flight Deck Sweeps", "Instant Situational Dominance", "Maximum Operational Power"]],
        [["Reasoning Alignment Flywheel", "Autonomous Cognitive Growth", "Fractional Compute Expense"], ["DeepSeek Benchmark Pioneer", "Frontier Scale Intelligence", "Production Certified Moat"]]
    ]
]

entries = []
for p_idx, part in enumerate(day49_dict['parts']):
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
    assert len(spec['title']) <= 75, f"Title too long: {spec['title']}"
    assert spec['title'].endswith('.'), f"Title must end with dot: {spec['title']}"
    assert not any(c.isdigit() for c in spec['title']), f"Title has digits: {spec['title']}"
    
    entry = {
        "partTitle": part['title'],
        "codeHash": code_hash,
        "spec": spec,
        "filled": spec
    }
    entries.append(entry)

visual_envelope = {
    "schemaVersion": "2.0.0",
    "prefix": "ai",
    "day": 49,
    "entries": entries
}

# Write lesson JSON to scripts/branch_c
with open("scripts/branch_c/day49_lesson.json", "w", encoding="utf-8") as f:
    json.dump(day49_dict, f, indent=2)

# Write visual envelope
with open("src/lib/data/lessonVisuals/ai/day-49.json", "w", encoding="utf-8") as f:
    json.dump(visual_envelope, f, indent=2)

print(f"Generated Day 49 lesson JSON ({total_words} words) and Visual Envelope successfully!")
