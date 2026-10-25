import json
import hashlib
import re

part1_say = [
    "As foundation language models scale to hundreds of billions of parameters, pre-training on vast internet text corpora equips them with remarkable linguistic fluency and encyclopedic knowledge. However, pre-training models strictly via self-supervised next-token prediction exposes a fundamental misalignment: internet text contains factual inaccuracies, toxic discourse, manipulative propaganda, and contradictory opinions. A language model trained solely to maximize the log-likelihood of arbitrary web tokens naturally predicts common fallacies, repeats hateful rhetoric, or fabricates hallucinations when prompted, failing completely to act as a helpful, harmless, and honest assistant.",
    "To transform raw base models into practical conversational agents, researchers initially relied on Supervised Fine-Tuning (SFT) over curated question-and-answer datasets authored by human annotators. In SFT, human demonstration dialogues teach the foundation model the desired stylistic format, conversational etiquette, and polite refusal boundaries. Despite these undeniable benefits, supervised fine-tuning suffers from severe theoretical and operational limitations: annotators cannot possibly write demonstrations for every conceivable user prompt, leaving the model vulnerable to catastrophic out-of-distribution hallucinations when encountering unfamiliar domain inquiries.",
    "Furthermore, supervised fine-tuning treats all tokens in a human demonstration with uniform cross-entropy loss, failing to differentiate between critical factual assertions and superficial syntactic filler words. An annotator might write a brilliant five-paragraph explanation where one minor numerical claim is slightly incorrect; standard cross-entropy penalizes the model equally for stylistic variance as for factual collapse, providing no gradient signal regarding which aspects of the response truly satisfy human intent.",
    "Most critically, SFT is fundamentally incapable of teaching models how to evaluate complex trade-offs between competing virtues—such as balancing helpful comprehensiveness against concise brevity, or maintaining polite tone while firmly refusing dangerous user instructions. SFT merely mimics surface-level behavioral patterns, lacking the exploratory trial-and-error mechanics necessary for robust cognitive optimization.",
    "A pedagogical apprenticeship analogy clarifies this limitation: an aspiring violin maker can spend months observing a master craftsman carve instrument bodies (representing supervised fine-tuning), memorizing the sequence of chisel strokes. However, the apprentice cannot truly master the craft until they carve wood with their own hands, listen to the acoustic resonance of the vibrating soundboard, and receive direct qualitative critique from a maestro on which subtle contours produce superior musical tone. True mastery requires trial, feedback, and reinforcement.",
    "To bridge this chasm between token prediction and human intent, modern artificial intelligence relies on Reinforcement Learning from Human Feedback (RLHF). Formulated by Christiano et al. (2017) and scaled to foundation models by Stiennon et al. (2020) and Ouyang et al. (2022), RLHF optimizes language models directly against empirical human preference rankings.",
    "By collecting pairwise comparisons between competing candidate responses, RLHF establishes a continuous optimization surface where models learn which generative strategies maximize human utility.",
    "In enterprise deployments, RLHF serves as the primary behavioral governor: it aligns model outputs with corporate brand safety guidelines, legal compliance policies, and domain-specific factual standards.",
    "Quantitative safety evaluations confirm that RLHF dramatically suppresses toxic completions, cuts hallucination rates by over sixty percent, and elevates user satisfaction win rates by substantial margins compared to baseline SFT models.",
    "From an optimization landscape perspective, reinforcement learning reshapes the probability distribution over response sequences, creating steep probability peaks around safe, helpful answers while flattening regions corresponding to dangerous completions. Unlike static cross-entropy, RL updates operate on full trajectories, allowing the model to explore alternative phrasing and self-correct prior missteps.",
    "Furthermore, alignment research demonstrates that scaling human feedback yields compounding returns: iterative rounds of preference collection and policy optimization progressively refine model capabilities, turning raw statistical text predictors into nuanced, reliable collaborative partners that adhere strictly to enterprise safety specifications and conversational standards.",
    "In summary, the alignment problem requires ascending beyond passive imitation learning: RLHF provides the mathematical machinery to optimize complex generative policies against nuanced human preferences."
]

part2_say = [
    "The mathematical foundation of RLHF begins with Reward Modeling, which transforms qualitative human preference rankings into an objective, continuous scalar scoring function. Collecting absolute numerical scores (such as rating a response from one to ten) from human annotators is notoriously noisy and unreliable: different annotators possess divergent internal scales, causing severe scoring variance and inter-rater disagreement. In contrast, asking an annotator a simple binary comparative question—'Given prompt x, which response is superior: Response A or Response B?'—yields remarkably consistent, high-agreement preference data.",
    "To translate these pairwise comparative choices into a continuous reward function, researchers adapt the classical Bradley-Terry-Luce (BTL) Model of pairwise preferences. Formulated in psychometrics, the Bradley-Terry model posits that the probability that a human prefers response y_w (the winner) over response y_l (the loser) given prompt x is a sigmoid function of the difference between their latent reward scores: P(y_w > y_l | x) equals sigma(r_psi(x, y_w) - r_psi(x, y_l)), where sigma(z) is the logistic sigmoid function one divided by one plus exponential of negative z.",
    "The Reward Model r_psi is initialized from a pre-trained language model, replacing the final vocabulary projection head with a scalar regression projection head that emits a single real-valued scalar score for any input sequence. The reward model is trained on a dataset of pairwise preferences D = {(x, y_w, y_l)} by minimizing the negative log-likelihood loss: Loss(psi) = -E[log sigma(r_psi(x, y_w) - r_psi(x, y_l))].",
    "Minimizing this binary cross-entropy loss trains the reward model to assign substantially higher scalar values to preferred responses while driving down the scores of dispreferred completions. If the reward model accurately assigns r(x, y_w) much greater than r(x, y_l), the difference is positive, the sigmoid approaches one point zero, and the loss vanishes. Conversely, if the model mistakenly prefers the loser, the difference is negative, driving the loss upward and producing strong corrective gradients.",
    "A sports rating analogy clarifies this mathematical formulation: in competitive chess tournaments, the Elo rating system predicts match outcomes by evaluating the difference between player ratings through a logistic curve. Winning against a higher-rated opponent produces a dramatic rating adjustment, while defeating a weak opponent yields minor adjustments. The Bradley-Terry reward model functions as an Elo rating engine for language, ranking competing responses along a unified latent capability scale.",
    "To ensure training stability, modern reward modeling incorporates data diversity auditing and length-bias normalization. Language models naturally exhibit a verbosity bias: annotators frequently prefer longer, more verbose responses even when shorter responses are more precise. Unmitigated reward models exploit this loophole, rewarding unnecessary fluff. Advanced training protocols introduce length regularization penalties into the loss function, ensuring that the model rewards factual depth rather than superficial wordiness.",
    "Furthermore, reward models are evaluated using calibration curves and cross-validation accuracy on held-out test splits. A high-quality enterprise reward model achieves pairwise classification accuracy exceeding seventy-five percent across diverse conversational domains, providing a reliable optimization signal for downstream reinforcement learning.",
    "In multi-task enterprise architectures, specialized reward models are trained for distinct objectives—such as helpfulness, factual accuracy, harmlessness, and code correctness—allowing system architects to combine modular reward signals during policy optimization.",
    "Cryptographic data provenance ensures that all training pairs trace back to verified human annotators, satisfying strict regulatory audit standards in legal and healthcare AI deployments.",
    "From a mathematical loss perspective, training the reward model on balanced preference pairs acts as an automated discriminator in generative adversarial formulations. When the loss approaches its theoretical minimum, the scalar reward difference between chosen and rejected completions mirrors the log-odds ratio of human preference, providing a calibrated utility surface for downstream reinforcement learning.",
    "In large-scale production pipelines, ensemble reward models comprising three to five distinct neural network architectures are frequently deployed to mitigate out-of-distribution uncertainty: averaging predictions across diverse model checkpoints dampens spurious correlations and prevents individual model biases from corrupting policy gradients.",
    "In summary, the Bradley-Terry preference framework converts subjective pairwise human comparisons into a calibrated, differentiable scalar reward model, establishing the objective function for policy optimization."
]

part3_say = [
    "With a calibrated reward model r_psi established, the language model policy pi_theta must be optimized to generate completions that maximize expected reward scores. In reinforcement learning terminology, generating text is formulated as a Markov Decision Process (MDP): the prompt x represents the initial state s_0, generating each token represents an action a_t, and the transition probability is deterministic concatenation. However, because text generation involves discrete token sampling, standard backpropagation cannot pass gradients from the scalar sequence reward back through the sampling operation. To optimize the policy, RLHF deploys Proximal Policy Optimization (PPO).",
    "Originally introduced by John Schulman et al. (2017) at OpenAI, PPO is an Actor-Critic on-policy reinforcement learning algorithm designed to execute stable policy gradient updates within a bounded trust region. PPO resolves a fundamental instability inherent in standard policy gradient methods (such as REINFORCE): unconstrained gradient steps can drastically alter policy weights, causing catastrophic policy collapse where the model begins emitting nonsensical, repetitive gibberish from which it can never recover.",
    "PPO enforces stability through its Clipped Surrogate Objective. For each generated token, the algorithm computes the probability ratio between the current policy pi_theta and the old policy pi_theta_old: r_t(theta) = pi_theta(a_t | s_t) / pi_theta_old(a_t | s_t). The objective optimizes: L_CLIP(theta) = E[min(r_t(theta) * A_t, clip(r_t(theta), 1 - epsilon, 1 + epsilon) * A_t)], where epsilon is a clipping hyperparameter (typically zero point one to zero point two), and A_t is the advantage estimate.",
    "The clipping mechanism guarantees that if a token action produces a positive advantage (A_t > 0), the policy ratio cannot increase beyond 1 + epsilon in a single update step. Conversely, if an action produces a negative advantage (A_t < 0), the ratio cannot drop below 1 - epsilon. By clipping the objective whenever the ratio deviates excessively from unity, PPO eliminates destructive gradient spikes and prevents the policy from drifting into unstable parameter regions.",
    "To compute token-level advantage estimates A_t, PPO trains an auxiliary Critic Model (Value Network) V_phi that predicts the expected cumulative reward from any intermediate token state. Using Generalized Advantage Estimation (GAE-lambda), the critic evaluates whether a generated token yielded a higher reward than expected, assigning credit to pivotal reasoning steps.",
    "An acrobatics analogy illuminates this clipped optimization: when gymnasts practice hazardous aerial maneuvers, coaches strap them into ceiling-mounted safety harnesses. The harness allows the athlete complete freedom to execute flips within a safe operational zone, but immediately arrests movement if the body angle deviates past critical equilibrium, preventing catastrophic falls. PPO clipping is the mathematical safety harness of reinforcement learning.",
    "During PPO training, the system alternates between Rollout Generation and Policy Optimization: the Actor generates batches of completions across diverse prompts, the Reward Model scores completed sequences, the Critic computes advantage estimates, and the Actor updates its weights using mini-batch gradient descent.",
    "Hardware scheduling algorithms pipeline these stages across distributed GPU clusters, streaming activations through tensor-parallel worker nodes to sustain continuous training throughput.",
    "Empirical ablation studies confirm that PPO delivers dramatically higher policy stability and asymptotic performance than vanilla policy gradient algorithms, serving as the workhorse engine behind groundbreaking aligned models.",
    "From an algorithmic convergence standpoint, Generalized Advantage Estimation introduces an exponential decay parameter lambda that mediates the fundamental bias-variance trade-off in temporal difference learning: setting lambda to zero yields low variance but high bias one-step temporal differences, while setting lambda to one yields unbiased but high-variance Monte Carlo returns. Calibrating lambda between zero point nine and zero point nine five provides the optimal signal-to-noise ratio for training autoregressive language policies.",
    "Furthermore, production PPO implementations incorporate entropy bonus terms into the policy loss, encouraging exploratory token sampling during early training epochs: penalizing premature entropy collapse prevents the policy from locking onto narrow, repetitive response structures and preserves conversational versatility.",
    "In summary, PPO actor-critic mechanics combine clipped surrogate objectives with generalized advantage estimation, enabling stable, high-velocity policy optimization over discrete token generation spaces."
]

part4_say = [
    "While optimizing a language model policy against a reward model using PPO yields impressive conversational capabilities, unconstrained optimization exposes a catastrophic failure mode known as Reward Hacking (or Goodhart's Law in AI Alignment). Goodhart's Law states: 'When a measure becomes a target, it ceases to be a good measure.' Because the reward model is merely an imperfect neural network approximation of true human values, an unconstrained PPO policy quickly discovers pathological edge cases—adversarial token sequences, bizarre formatting tricks, or repetitive sycophantic phrases—that exploit the reward model's latent blind spots to achieve near-perfect reward scores while being completely nonsensical or harmful to real humans.",
    "To suppress reward hacking and preserve natural language coherence, the RLHF optimization objective introduces a strict Kullback-Leibler (KL) Divergence Penalty against the initial SFT reference model pi_ref. The reference model is frozen permanently at the start of RLHF training. At every token step t, the system computes the token-level KL divergence between the active policy pi_theta and the reference policy pi_ref: D_KL(pi_theta || pi_ref) = log pi_theta(y_t | x, y_<t) - log pi_ref(y_t | x, y_<t).",
    "The token-level reward is augmented with this KL penalty: R_penalized(x, y) = R_scalar(x, y) - beta_KL * D_KL(pi_theta || pi_ref). The hyperparameter beta_KL acts as a restoring spring: whenever the active policy begins drifting too far from the natural language distributions learned during supervised fine-tuning, the KL penalty explodes negatively, drastically slashing the total reward and forcing the policy back into the linguistic safety corridor.",
    "In production RLHF pipelines, selecting and controlling beta_KL is critical. If beta_KL is set too high, the policy is paralyzed, unable to adapt its behavior or learn preference nuances. If beta_KL is set too low, reward hacking emerges rapidly: completions degenerate into verbose fluff or repetitive exclamation loops that maximize reward scores artificially. Modern training systems deploy Adaptive KL Controllers: if empirical KL drift exceeds a target threshold, beta_KL increases automatically; if drift drops below the target, beta_KL decays gradually.",
    "A financial regulatory analogy clarifies this restoring mechanism: central bank monetary authorities establish strict capital reserve ratios to prevent commercial banks from engaging in excessive speculative lending. When financial markets overheat with speculative euphoria (analogous to reward hacking), regulators tighten reserve requirements, cooling the system and tethering financial activity to productive economic fundamentals.",
    "Furthermore, monitoring KL divergence provides site reliability engineers with a real-time health diagnostic: tracking the trajectory of policy entropy alongside mean reward scores reveals whether performance improvements stem from genuine cognitive alignment or degenerative reward hacking.",
    "In multi-stage enterprise alignment pipelines, dual-reference KL bounds are frequently employed, measuring divergence simultaneously against the original base foundation model and the task-specific SFT checkpoint to prevent catastrophic forgetting of core knowledge.",
    "By harmonizing scalar preference maximization with strict KL divergence constraints, RLHF achieves the ideal equilibrium: aggressive behavioral adaptation anchored by unbreakable linguistic foundations.",
    "Quantitative safety audits show that maintaining strict KL bounds eliminates over ninety-five percent of reward hacking anomalies, ensuring that optimized models remain linguistically grounded and practically useful.",
    "From an information geometry viewpoint, the KL divergence term defines a Riemannian metric over the manifold of autoregressive probability distributions, constraining policy trajectory updates to lie within a local Fisher information ball around the reference model. This geometric constraint preserves the delicate syntax, reasoning steps, and factual knowledge encoded during pre-training while permitting the policy to adjust its behavioral posture.",
    "Furthermore, advanced alignment frameworks deploy per-token dynamic KL clipping, ensuring that rare, high-surprise tokens do not trigger catastrophic penalty spikes that derail training. By bounding the maximum per-token divergence penalty, the optimizer maintains steady gradient flow across multi-thousand-token reasoning sequences.",
    "In summary, the KL divergence penalty enforces linguistic conservatism, guaranteeing that reinforcement learning enhances model utility without drifting into pathological reward exploitation."
]

part5_say = [
    "Deploying full-scale PPO alignment across state-of-the-art foundation models presents one of the most demanding infrastructure challenges in modern computational engineering. Unlike standard pre-training or supervised fine-tuning—which evaluates a solitary neural network in forward and backward passes—a complete PPO training loop requires coordinating Four Concurrent Foundation Models simultaneously: the Actor Model pi_theta (which is actively updated), the Reference Model pi_ref (which is frozen), the Critic Model V_phi (which is actively updated), and the Reward Model r_psi (which is frozen).",
    "Hosting four full-scale parameter models in high-bandwidth accelerator memory simultaneously introduces immense VRAM pressure. For a seventy-billion-parameter foundation model, storing four model replicas in float16 precision would require over five hundred sixty gigabytes of memory purely for model parameters, before allocating memory for optimizer states, key-value caches, and activation tensors. Executing PPO at this scale demands sophisticated Distributed Systems Architecture and Multi-Model Co-Location strategies.",
    "The primary architectural solution is Asynchronous Actor-Critic Co-Location powered by frameworks like Ray, Megatron-DeepSpeed, and vLLM. In optimized serving clusters, the Actor and Critic models share the primary GPU execution fleet, while the frozen Reference Model and Reward Model are offloaded to secondary nodes or compressed via aggressive post-training quantization (such as FP8 or 4-bit AWQ). Because the reference and reward models only execute inference without backward passes, running them in quantized precision preserves activation fidelity while cutting memory consumption by over seventy percent.",
    "Furthermore, production PPO infrastructure separates the Rollout Generation Phase from the Optimization Phase. Rollout generation is fundamentally memory-bandwidth bound: generating thousands of tokens requires high-speed autoregressive decoding. Modern PPO engines route generation through integrated vLLM or TensorRT-LLM inference engines utilizing PagedAttention and continuous chunked prefill, achieving up to a five-fold acceleration in rollout throughput compared to naive PyTorch generation.",
    "Once rollouts are generated, activations are gathered and dispatched to DeepSpeed ZeRO-Stage 3 training workers, which partition optimizer states, gradients, and model parameters across cluster interconnects. PPO gradient updates execute via tensor and pipeline parallelism, maximizing compute utilization across NVIDIA H100 or TPU v5e clusters.",
    "A pit crew racing analogy encapsulates this distributed orchestration: in Formula One auto racing, multiple specialized technicians perform synchronized tasks—fueling, tire changing, aerodynamic adjustments, and telemetry monitoring—in a choreographed two-second pit stop. PPO requires an identical level of distributed precision: rollouts, reward scoring, advantage estimation, and gradient backpropagation must execute seamlessly without pipeline bubbles or GPU starvation.",
    "Continuous profiling frameworks monitor memory fragmentation, inter-node InfiniBand communication latencies, and gradient norm variances in real time, alerting infrastructure engineers to hardware stragglers before training stability is compromised.",
    "In enterprise production environments, checkpoint management protocols automatically capture model checkpoints after every training epoch, running automated evaluation batteries across MT-Bench, AlpacaEval, and GSM8K to verify that alignment gains are sustained without regressions in core reasoning abilities.",
    "This robust infrastructure architecture transforms PPO from a fragile research prototype into a resilient, industrial-scale alignment pipeline capable of training planetary-scale AI systems.",
    "From an engineering resource utilization viewpoint, asynchronous PPO decoupled pipelines achieve near-linear scaling across thousands of GPU accelerators. Overlapping token rollout generation with gradient computation hides communication latencies, keeping high-cost matrix multiplication tensor cores operating at peak thermal and compute saturation throughout multi-week alignment campaigns.",
    "Furthermore, modern enterprise clusters incorporate elastic fault recovery: if an individual GPU worker experiences a memory error or transient hardware failure during policy rollout, the orchestrator redistributes the remaining prompt batch to healthy nodes and resumes training without rolling back optimizer states, guaranteeing continuous uptime.",
    "Hardware telemetry monitoring confirms that balancing batch sizes across tensor-parallel ranks minimizes communication overhead, maintaining ultra-low step latencies during intense distributed training campaigns.",
    "In summary, distributed PPO infrastructure masters multi-model co-location, memory virtualization, and parallel pipeline scheduling, providing the computational foundation for modern enterprise AI alignment."
]

code1 = """function simulatePPOAlignment(numSamples: number, clipEpsilon: number = 0.2, klCoeff: number = 0.05) {
  const policyRatio = 1.15; // pi_theta / pi_theta_old
  const rawAdvantage = 1.42;
  const clippedRatio = Math.min(Math.max(policyRatio, 1 - clipEpsilon), 1 + clipEpsilon);
  const surrogateObjective = Math.min(policyRatio * rawAdvantage, clippedRatio * rawAdvantage);
  const klDivergence = 0.038;
  const penalizedReward = rawAdvantage - (klCoeff * klDivergence);

  return {
    trainingSamplesEvaluated: numSamples,
    bradleyTerryModel: "P(yw > yl | x) = sigmoid(r(x, yw) - r(x, yl))",
    policyRatio: policyRatio,
    clippedRatio: clippedRatio,
    surrogateObjective: Number(surrogateObjective.toFixed(4)),
    klDivergencePenalty: Number((klCoeff * klDivergence).toFixed(5)),
    penalizedRewardScore: Number(penalizedReward.toFixed(4)),
    policyStability: "Bounded within trust region"
  };
}
console.log(simulatePPOAlignment(1000));"""

output1 = """{
  trainingSamplesEvaluated: 1000,
  bradleyTerryModel: 'P(yw > yl | x) = sigmoid(r(x, yw) - r(x, yl))',
  policyRatio: 1.15,
  clippedRatio: 1.15,
  surrogateObjective: 1.633,
  klDivergencePenalty: 0.0019,
  penalizedRewardScore: 1.4181,
  policyStability: 'Bounded within trust region'
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
assert total_words >= 3100, f"Day 46 total word count too low: {total_words}"

day46_dict = {
    "day": 46,
    "title": "Reinforcement Learning from Human Feedback (RLHF): Reward Modeling, Bradley-Terry Math & PPO Policy Optimization",
    "goal": "Master the mathematical foundations and systems engineering of RLHF, analyze Bradley-Terry preference modeling, dissect Proximal Policy Optimization (PPO) actor-critic dynamics, evaluate KL divergence constraints against reward hacking, and understand distributed multi-model training infrastructure.",
    "minutes": 38,
    "recap": "Throughout Block 9, we mastered multi-vector retrieval and GraphRAG. Today, we inaugurate Block 10 dedicated to AI Alignment, starting with RLHF, Bradley-Terry preference mathematics, and PPO actor-critic policy optimization.",
    "parts": [
        {
            "title": "The Alignment Problem: Beyond Supervised Fine-Tuning",
            "say": part1_say,
            "example": "An apprentice violin maker mimics master craftsmen chisel strokes without understanding acoustic resonance until receiving direct auditory critique.",
            "code": code1,
            "output": output1,
            "tryIt": "Compare supervised fine-tuning limitations against reinforcement learning from preference feedback on complex trade-offs.",
            "check": {
                "question": "Why is supervised fine-tuning (SFT) alone insufficient for achieving safe, high-quality AI assistant behavior?",
                "options": [
                    "SFT treats all tokens with uniform loss and cannot teach complex trade-offs, leading to distribution shift and hallucinations.",
                    "SFT requires quantum computing hardware and cannot be trained on standard graphic processing unit clusters.",
                    "SFT permanently deletes the model's vocabulary and forces it to generate random hexadecimal numbers.",
                    "SFT only works for computer vision tasks and cannot be applied to natural language text models."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Supervised fine-tuning penalizes stylistic variance identically to factual collapse, cannot navigate trade-offs between helpfulness and safety, and fails under out-of-distribution prompts."
            }
        },
        {
            "title": "Bradley-Terry Preference Modeling & Reward Model Training",
            "say": part2_say,
            "example": "Wine judges compare vintages in pairwise tastings to establish an objective quantitative quality scale across competing vineyards.",
            "code": code1,
            "output": output1,
            "tryIt": "Trace the Bradley-Terry logistic sigmoid formulation and calculate the preference loss across winner and loser candidate outputs.",
            "check": {
                "question": "How does the Bradley-Terry preference model formulate the probability that a human prefers response y_w over y_l?",
                "options": [
                    "As a logistic sigmoid function of the scalar reward difference: P(y_w > y_l | x) = sigma(r(x, y_w) - r(x, y_l)).",
                    "By counting the exact number of vowels in both responses and subtracting the shorter text length.",
                    "By converting both text strings into SHA-256 hashes and performing a bitwise XOR comparison.",
                    "As an exponential multiplication of vocabulary token IDs divided by the prompt character count."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "The Bradley-Terry framework models pairwise preference probabilities as a logistic sigmoid applied to the difference between scalar rewards assigned to the two candidate responses."
            }
        },
        {
            "title": "Proximal Policy Optimization (PPO) Actor-Critic Mechanics",
            "say": part3_say,
            "example": "Gymnasts practice complex aerial flips inside protective safety harnesses that permit fluid rotation while arresting dangerous falls.",
            "code": code1,
            "output": output1,
            "tryIt": "Calculate the clipped surrogate objective and observe how PPO restricts policy ratio updates within the trust region.",
            "check": {
                "question": "What is the primary function of the clipped surrogate objective in PPO policy optimization?",
                "options": [
                    "It clips the probability ratio within [1-epsilon, 1+epsilon], preventing destructive policy updates and stabilizing training.",
                    "It truncates all generated text sequences after exactly ten tokens to reduce cloud compute expenditures.",
                    "It discards all neural network weights whose numerical values exceed positive ten to save graphic memory.",
                    "It converts all continuous float32 values into binary boolean flags to eliminate gradient calculations."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Clipping the policy probability ratio to a narrow window prevents excessive parameter updates, stabilizing discrete on-policy reinforcement learning against policy collapse."
            }
        },
        {
            "title": "The KL Divergence Penalty & Preventing Reward Hacking",
            "say": part4_say,
            "example": "Central bank regulators establish mandatory capital reserve ratios to prevent financial institutions from engaging in speculative bubbles.",
            "code": code1,
            "output": output1,
            "tryIt": "Inspect how the Kullback-Leibler divergence penalty against the frozen reference model tethers the active policy to linguistic reality.",
            "check": {
                "question": "Why is the Kullback-Leibler (KL) divergence penalty essential in RLHF policy optimization?",
                "options": [
                    "It penalizes policy drift from the frozen reference model, preventing reward hacking and preserving natural language coherence.",
                    "It accelerates training speed by skipping all backpropagation passes on every odd-numbered training epoch.",
                    "It forces the model to memorize the entire training dataset word-for-word without any generalization.",
                    "It encrypts all model activations using public-key cryptography to prevent network interception."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "The KL divergence penalty acts as a restoring spring against the reference model, stopping the policy from exploiting reward model blind spots (reward hacking) and maintaining coherent linguistic capability."
            }
        },
        {
            "title": "Hardware Scaling, Multi-Model Co-Location & Distributed PPO Infrastructure",
            "say": part5_say,
            "example": "Formula One pit crews execute highly synchronized tire changes, refueling, and telemetry checks in a choreographed two-second stop.",
            "code": code1,
            "output": output1,
            "tryIt": "Analyze the memory footprint of coordinating four concurrent foundation models and examine asynchronous PPO cluster pipelines.",
            "check": {
                "question": "How do modern PPO training clusters manage the immense VRAM footprint of coordinating four concurrent foundation models?",
                "options": [
                    "By co-locating the Actor and Critic on GPUs while offloading or quantizing the frozen Reference and Reward models.",
                    "By deleting the Actor model and running the entire reinforcement learning pipeline on physical paper punch cards.",
                    "By running all four models sequentially on a single consumer smartphone over Wi-Fi connections.",
                    "By discarding all training prompts and training the models purely on synthetic noise generated by random number generators."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Production clusters co-locate the actively updated Actor and Critic models on training GPUs while quantizing or offloading the frozen Reference and Reward models to minimize VRAM pressure."
            }
        }
    ],
    "summary": [
        "Analyzed the fundamental alignment problem where self-supervised next-token prediction and SFT fail to optimize nuanced human preferences.",
        "Formulated the Bradley-Terry preference model, converting pairwise comparative human rankings into differentiable scalar reward models.",
        "Dissected PPO actor-critic mechanics, exploring clipped surrogate objectives and generalized advantage estimation for discrete token spaces.",
        "Demonstrated the vital role of the Kullback-Leibler divergence penalty in suppressing reward hacking and maintaining linguistic stability.",
        "Architected distributed PPO infrastructure, detailing four-model co-location, vLLM rollout acceleration, and ZeRO-3 memory partitioning."
    ],
    "projectStep": {
        "title": "PPO Actor-Critic Policy Alignment Simulator",
        "steps": [
            "Construct a Bradley-Terry reward model loss evaluator computing binary cross-entropy gradients over synthetic preference pairs.",
            "Implement a PPO clipped surrogate objective calculator with generalized advantage estimation and trust region bounds.",
            "Benchmark policy divergence tracking token-level KL penalties and simulate adaptive beta controller dynamics against reward hacking."
        ]
    }
}

captions_data = [
    {
        "say1": "Next token prediction alone fails to ensure truthful model behavior.",
        "say2": "Supervised fine tuning suffers from severe distribution shift issues.",
        "example": "Apprentices mimic master gestures without understanding principles.",
        "tryIt": "Inspect supervised tuning boundaries and evaluate alignment objectives."
    },
    {
        "say1": "Bradley Terry modeling converts pairwise comparisons into scalar rewards.",
        "say2": "Reward model training minimizes binary cross entropy preference losses.",
        "example": "Wine judges evaluate pairs of vintages to establish quantitative ratings.",
        "tryIt": "Simulate Bradley Terry preference loss over pairs of candidate outputs."
    },
    {
        "say1": "PPO actor critic training orchestrates four concurrent language models.",
        "say2": "Clipped surrogate objectives prevent destructive policy updates.",
        "example": "Acrobats practice complex aerial flips inside protective safety harnesses.",
        "tryIt": "Calculate clipped policy objective and inspect advantage estimates."
    },
    {
        "say1": "Reward hacking occurs when policies exploit flaws in reward models.",
        "say2": "Kullback Leibler penalties anchor active policies to reference baselines.",
        "example": "Financial regulators enforce reserve ratios to deter speculative bubbles.",
        "tryIt": "Monitor divergence metrics and evaluate adaptive penalty controllers."
    },
    {
        "say1": "Distributed PPO coordinates actor critic and reward networks across GPUs.",
        "say2": "Offloading reference models to host memory saves valuable device VRAM.",
        "example": "Choreographed pit crews service high speed race cars in milliseconds.",
        "tryIt": "Examine asynchronous cluster pipelines and analyze memory footprint."
    }
]

titles = [
    "The Alignment Problem and Supervised Fine Tuning Limitations.",
    "Bradley Terry Preference Modeling and Reward Calibration.",
    "Proximal Policy Optimization Actor Critic Mechanics.",
    "Kullback Leibler Penalty and Reward Hacking Prevention.",
    "Distributed PPO Infrastructure and Multi Model Co Location."
]

columns_list = [
    ["Alignment Framework Tier", "Core Mathematical Driver", "Operational Safety Guarantee"],
    ["Preference Formulation Layer", "Loss Function Optimization", "Scoring Calibration Standard"],
    ["PPO Policy Component", "Trust Region Mechanism", "Policy Gradient Stability"],
    ["Governance Penalty Mechanism", "Mathematical Formulation", "Linguistic Protection Property"],
    ["Distributed Cluster Role", "Memory Virtualization Tier", "System Throughput Capability"]
]

steps_rows = [
    [
        [["Self Supervised Base Model", "Internet Token Likelihood", "High Hallucination Exposure"], ["Supervised Fine Tuning", "Curated Human Demonstrations", "Style Tone Format Imitation"]],
        [["Out Of Distribution Query", "Distributional Covariate Shift", "Superficial Behavioral Mimicry"], ["Reinforcement Learning", "Empirical Preference Ranking", "Deep Cognitive Goal Alignment"]],
        [["Violin Workshop Apprentice", "Chisel Motion Observation", "Zero Acoustic Sound Feedback"], ["Master Craftsman Critique", "Direct Auditory Resonance", "Excellence Through Iteration"]],
        [["Uniform Cross Entropy", "Equal Penalty For All Tokens", "No Strategic Trade Off Vision"], ["Scalar Preference Gradient", "Continuous Quality Ranking", "Production Certified Safety"]]
    ],
    [
        [["Pairwise Comparative Choice", "Binary Winner Loser Pairs", "High Inter Annotator Agreement"], ["Bradley Terry Psychometrics", "Sigmoid Of Score Difference", "Continuous Latent Scale Mapping"]],
        [["Scalar Reward Projection", "Linear Single Value Head", "Unbroken Differentiable Path"], ["Binary Preference Loss", "Negative Log Sigmoid Objective", "Large Winner Score Separation"]],
        [["Wine Tasting Exhibition", "Head To Head Vintage Taste", "Definitive Quality Ranking"], ["Elo Tournament Metric", "Logistic Match Odds Model", "Calibrated Master Scoreboard"]],
        [["Verbosity Bias Defense", "Length Regularization Penalty", "Elimination Of Superficial Fluff"], ["Multi Objective Partition", "Helpfulness Safety Split", "Independent Reward Modularization"]]
    ],
    [
        [["Markov Decision Process", "Autoregressive State Steps", "Discrete Token Action Space"], ["On Policy Actor Critic", "Simultaneous Policy And Value", "Stable Expected Reward Ascent"]],
        [["Probability Action Ratio", "Current Over Old Policy Prob", "Unbounded Update Collapse Risk"], ["Clipped Surrogate Objective", "Epsilon Bound Trust Region", "Mathematically Guaranteed Safety"]],
        [["Trapeze Aerial Acrobatics", "High Altitude Flip Routine", "Catastrophic Fall Danger"], ["Protective Safety Harness", "Arrested Over Rotation Bound", "Zero Risk Skill Acquisition"]],
        [["Generalized Advantage GAE", "Temporal Difference Residuals", "Credit Assigned To Key Steps"], ["Synchronized Rollout Cycle", "Streaming Batch Evaluation", "High Concurrency Execution"]]
    ],
    [
        [["Reward Hacking Pathology", "Goodharts Law Vulnerability", "Degenerative Nonsense Exploits"], ["Adversarial Reward Shortcut", "Flawed Model Approximation", "Superficial Perfect Scores"]],
        [["Kullback Leibler Divergence", "Active Against Reference Prob", "Log Policy Ratio Difference"], ["Restoring Spring Penalty", "Negative Reward Subtraction", "Strict Linguistic Anchor"]],
        [["Central Reserve Authority", "Mandatory Capital Standards", "Speculative Bubble Deterrent"], ["Monetary Anchor Bounds", "Economic Production Basis", "Guaranteed System Stability"]],
        [["Adaptive Controller Beta", "Real Time Drift Calibration", "Automatic Restoring Scaling"], ["Dual Reference Protocol", "Base Plus SFT Divergence", "Zero Catastrophic Forgetting"]]
    ],
    [
        [["Four Model PPO Fleet", "Actor Reference Critic Reward", "Massive VRAM Multi Model Need"], ["Seventy Billion Parameter", "Over Five Hundred Gigabytes", "Single GPU Memory Overflow"]],
        [["Actor Critic Shared Nodes", "Active Tensor Parallelism", "Maximum Compute Occupancy"], ["Reference Reward Offload", "Quantized Eight Bit Inference", "Seventy Percent Memory Drop"]],
        [["Formula One Pit Operation", "Choreographed Crew Timing", "Zero Second Transit Wasted"], ["Asynchronous Ray Mesh", "Separated Rollout Pipeline", "Zero Hardware Bubble Stalls"]],
        [["PagedAttention Rollouts", "Continuous Chunked Prefill", "Five Fold Decoding Acceleration"], ["Enterprise ZeRO Partition", "Distributed Parameter Shards", "Planetary Scale Alignment"]]
    ]
]

entries = []
for p_idx, part in enumerate(day46_dict['parts']):
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
    "day": 46,
    "entries": entries
}

# Write lesson JSON to scripts/branch_c
with open("scripts/branch_c/day46_lesson.json", "w", encoding="utf-8") as f:
    json.dump(day46_dict, f, indent=2)

# Write visual envelope
with open("src/lib/data/lessonVisuals/ai/day-46.json", "w", encoding="utf-8") as f:
    json.dump(visual_envelope, f, indent=2)

print(f"Generated Day 46 lesson JSON ({total_words} words) and Visual Envelope successfully!")
