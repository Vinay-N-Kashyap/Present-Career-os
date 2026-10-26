import json
import hashlib
import re

part1_say = [
    "As artificial intelligence alignment architectures matured from complex reinforcement learning loops like PPO to streamlined direct objectives like DPO, a fundamental practical bottleneck emerged not in the mathematical algorithms, but in the Data Annotation Pipeline: The Tyranny of Pairs. Both Bradley-Terry reward modeling and Direct Preference Optimization depend strictly on paired preference datasets D = {(x, y_w, y_l)}. For every training instance, human annotators or synthetic judges must be presented with a prompt and two full candidate completions, carefully reading and contrasting both texts to declare a definitive winner and loser.",
    "In real-world enterprise operations, collecting high-quality paired preference data is prohibitively expensive, cognitively exhausting, and operationally slow. Evaluating two multi-paragraph technical answers—such as contrasting two distinct software architecture proposals, two complex legal contract analyses, or two medical treatment syntheses—requires human annotators to spend significant cognitive effort analyzing subtle trade-offs. As human fatigue sets in, inter-annotator agreement plummets, introducing noisy, inconsistent labels that distort alignment gradients.",
    "Most critically, the requirement for paired comparisons disconnects alignment algorithms from the vast ocean of Real-World Enterprise Telemetry. When millions of enterprise employees, consumers, and customer service agents interact with deployed conversational models, they almost never generate paired data! Users do not read two alternative answers and pick the better one; instead, they interact with a single generated completion and provide Unpaired Binary Feedback: a thumbs-up upvote, a thumbs-down downvote, an accepted code completion, a copied text snippet, or an abandoned session.",
    "Under standard DPO or PPO pipelines, this massive reservoir of natural user feedback cannot be ingested directly. Engineering teams are forced to deploy awkward, synthetic pairing heuristics—such as pairing an upvoted answer with a randomly sampled downvoted answer from an entirely different user session—which introduces severe context mismatch and confounding variables that disrupt training.",
    "A consumer product testing analogy highlights this operational dilemma: when a beverage company conducts market research, asking consumers to taste twenty pairs of unmarked soda formulations in a laboratory (paired testing) is slow and expensive. In contrast, tracking which soda cans consumers actually purchase from grocery store shelves (unpaired binary feedback) yields millions of high-fidelity, real-world preference signals at near-zero incremental cost. Aligning AI systems requires learning directly from unpaired user actions.",
    "To unlock the full power of real-world binary feedback, researchers at Stanford University and Contextual AI developed Kahneman-Tversky Optimization (KTO) in early 2024. Grounded in Nobel Prize-winning behavioral economics, KTO fundamentally frees AI alignment from the tyranny of pairs, allowing models to learn directly from unpaired desirable and undesirable completions.",
    "From an enterprise data perspective, KTO transforms raw application telemetry into an immediate alignment training asset, eliminating expensive manual annotation vendors and accelerating deployment cycles.",
    "Furthermore, mathematical analysis confirms that KTO matches or exceeds DPO performance on standard conversational benchmarks while training on significantly cheaper, more abundant unpaired data.",
    "In continuous production environments, KTO enables true real-time self-improvement loops: user interactions from morning customer support queues can be fed directly into evening alignment runs without intermediate pairing pipelines.",
    "This operational revolution bridges the divide between academic alignment theory and enterprise telemetry realities, establishing the modern foundation for scalable, data-efficient AI optimization.",
    "From an engineering resource utilization viewpoint, eliminating the requirement for synchronized paired text generation radically simplifies data pipelines. Enterprise data engineers can ingest raw user interaction logs from distributed microservices without constructing complex offline graph joins or synthetic pairing heuristics.",
    "Furthermore, continuous user feedback exhibits natural temporal variance: as enterprise products release new features or update corporate policies, user upvotes and downvotes immediately capture shifting expectations, allowing alignment algorithms to track organizational evolution in real time.",
    "In summary, the high cost and artificial constraints of paired preference annotation created the imperative for unpaired alignment, inspiring the behavioral economics breakthrough of KTO."
]

part2_say = [
    "The intellectual brilliance of Kahneman-Tversky Optimization (KTO) is its profound theoretical grounding in Human Behavioral Economics. In classical utility theory, economists assumed that humans make decisions by maximizing expected utility along a linear, symmetric scale: gaining one hundred dollars brings the exact same magnitude of psychological satisfaction as losing one hundred dollars brings psychological distress. In 1979, psychologists Daniel Kahneman and Amos Tversky demolished this assumption through Prospect Theory, which earned Daniel Kahneman the Nobel Prize in Economic Sciences in 2002.",
    "Prospect Theory established that human decision-making deviates systematically from linear expected utility in two fundamental ways: Reference Point Dependence (humans evaluate outcomes as gains or losses relative to a neutral reference point, rather than assessing absolute wealth states) and Loss Aversion (humans experience the psychological pain of a loss approximately twice as intensely as the pleasure of an equivalent gain: losses loom larger than gains). Empirical studies across behavioral economics consistently reveal a loss aversion multiplier lambda between one point five and two point five.",
    "The creators of KTO—Kawin Ethayarajh, Winnie Xu, Niklas Muennighoff, Dan Jurafsky, and Douwe Kiela—realized that human satisfaction with AI conversational outputs obeys identical psychological principles! When a user prompts an AI assistant, they do not evaluate completions along an absolute mathematical scale. If the model produces a helpful, accurate answer, the user feels a modest positive gain. However, if the model produces a toxic insult, a blatant hallucination, or a security violation, the user experiences intense negative distress that completely destroys trust in the system.",
    "To model this asymmetric human psychology, KTO formulates a Prospect Utility Function v_KTO that processes unpaired examples (x, y) tagged with a binary label indicating whether the completion is Desirable (label +1) or Undesirable (label -1). The implicit reward is measured via the policy log-probability ratio relative to a reference model: z(x, y) = log(pi_theta(y|x) / pi_ref(y|x)).",
    "KTO defines the prospect value function as: v_KTO(x, y) = sigma(lambda_D * (z(x, y) - z_ref)) if y is Desirable, and v_KTO(x, y) = sigma(lambda_U * (z_ref - z(x, y))) if y is Undesirable, where lambda_D and lambda_U are scaling parameters that encode human loss aversion (with lambda_U > lambda_D), and z_ref is the neutral reference baseline.",
    "The KTO loss function directly maximizes expected human prospect utility: L_{KTO}(theta; pi_ref) = E_{(x, y)} [w(y) * (1 - v_KTO(x, y))], where w(y) is a weighting hyperparameter that balances desirable and undesirable sample distributions in training batches.",
    "A financial portfolio analogy illustrates this asymmetric prospect valuation: an investor who gains ten thousand dollars in the stock market celebrates mildly over dinner; that same investor, upon losing ten thousand dollars, experiences visceral panic, sleepless nights, and profound anxiety. Human psychology is deeply risk-averse and loss-intolerant. KTO embeds this fundamental human truth into the loss function, ensuring models prioritize avoiding harmful blunders above generating showy rhetoric.",
    "From an optimization perspective, KTO operates smoothly on heterogeneous batches containing arbitrary ratios of upvoted and downvoted responses, eliminating the requirement that every positive example must have a paired negative counterpart.",
    "Furthermore, mathematical proofs establish that maximizing KTO prospect utility asymptotically maximizes human satisfaction under Prospect Theory, aligning models with authentic human cognition rather than idealized mathematical assumptions.",
    "In enterprise AI safety applications, tuning the loss aversion multiplier lambda_U allows compliance officers to enforce strict safety margins: increasing lambda_U heavily penalizes compliance infractions without degrading general helpfulness.",
    "From a mathematical loss perspective, the asymmetric Kahneman-Tversky value function introduces differential curvature into policy gradient updates: when evaluating undesirable outputs, the steeper gradient slope drives active parameter updates to suppress prohibited phrases rapidly, while desirable outputs receive moderate, steady positive reinforcement that preserves linguistic diversity.",
    "Furthermore, cognitive science studies demonstrate that human trust in automated systems exhibits an identical asymmetric hysteresis: building user trust requires dozens of helpful interactions, but a single catastrophic hallucination destroys trust instantly. By embedding loss aversion directly into the mathematical objective, KTO aligns generative policies with real-world trust dynamics.",
    "In summary, KTO synthesizes Nobel Prize-winning prospect theory with foundation model alignment, leveraging human loss aversion to optimize models directly on unpaired binary feedback."
]

part3_say = [
    "To implement Kahneman-Tversky Optimization effectively in production systems, engineers must understand the mechanics of Reference Point Shifting and Unpaired Binary Optimization. In standard DPO, the comparison between preferred y_w and dispreferred y_l provides an inherent self-referencing baseline: the model computes the difference between two competing completions for the exact same prompt, canceling out prompt-specific difficulty factors.",
    "In contrast, because KTO processes solitary, unpaired completions (x, y), it must establish an objective Reference Point z_ref to determine whether a given completion constitutes a positive psychological gain or a negative psychological loss. Without a well-calibrated reference point, a difficult prompt that naturally yields lower log-probabilities across all completions might be mistakenly penalized as an undesirable failure.",
    "In the KTO mathematical framework, the reference point z_ref is defined as the expected Kullback-Leibler divergence between the active policy and the reference model across the prompt distribution: z_ref = E_{x' ~ D} [D_{KL}(pi_theta(y|x') || pi_ref(y|x'))]. In practical training implementations, z_ref is estimated dynamically using an exponentially moving average (EMA) of token log-ratios across recent training batches, or computed directly across a fixed validation anchor set.",
    "When an incoming completion achieves a log-ratio z(x, y) that exceeds z_ref, the value function treats the outcome as a positive psychological gain, generating positive reinforcement gradients. Conversely, when a completion falls below z_ref, the value function treats it as a psychological loss, applying aggressive corrective penalties scaled by the loss aversion multiplier lambda_U.",
    "This dynamic reference baseline enables KTO to achieve complete Decoupling of Positive and Negative Feedback: the dataset can contain ten thousand positive upvotes from one customer demographic and two thousand downvotes from a completely different domain, yet KTO processes both seamlessly within the same unified loss formulation.",
    "A performance benchmarking analogy clarifies this reference point mechanism: in professional golf tournaments, players do not compete head-to-head in synchronized duels; instead, every player competes against Par (the standardized course baseline representing z_ref). Scoring below par represents a birdie (a desirable gain), while scoring above par represents a bogey (an undesirable loss). Every player's performance is independently evaluated against the fixed course reference.",
    "Furthermore, empirical ablation studies confirm that dynamic reference point tracking prevents gradient instability: as the active policy evolves across training epochs, z_ref adjusts smoothly, maintaining consistent prospect utility gradients without saturation or vanishing gradients.",
    "In multi-modal enterprise settings, reference point baselines normalize scoring differences across distinct input modalities: complex code generation prompts naturally exhibit different baseline entropy than simple customer greetings, and dynamic reference shifting ensures equitable optimization across all task types.",
    "Hardware execution profiling demonstrates that KTO training runs with identical memory footprint and compute efficiency to DPO, while unlocking access to vastly larger enterprise telemetry datasets.",
    "From an optimization convergence standpoint, tracking the dynamic reference point prevents gradient saturation when training on long-tailed domain prompts: prompts requiring deep mathematical or legal analysis naturally produce different log-likelihood distributions than conversational greetings, and dynamic reference adaptation ensures that each task category is evaluated against its appropriate difficulty baseline.",
    "Furthermore, system architects frequently implement stratified reference baselines: maintaining separate moving average reference points across distinct functional task tags (such as code generation, factual Q&A, and creative writing) provides fine-grained normalization that accelerates multi-task convergence.",
    "In continuous deployment environments, reference point stability metrics serve as an automated anomaly detection sentinel: sudden unexpected shifts in z_ref alert engineering teams to data distribution drift or corrupted telemetry logs before model weights are updated during scheduled fine-tuning runs across distributed clusters.",
    "Hardware execution profiling demonstrates that KTO training runs with identical memory footprint and compute efficiency to DPO, while unlocking access to vastly larger enterprise telemetry datasets across planetary infrastructure environments.",
    "In summary, dynamic reference point shifting establishes a standardized baseline against which unpaired completions are evaluated, enabling robust, loss-averse policy optimization over real-world binary data."
]

part4_say = [
    "While direct preference algorithms like DPO and KTO offer immense operational advantages over PPO, rigorous empirical analysis reveals a subtle and dangerous mathematical pathology known as Over-Optimization and Policy Degeneration. In 2023, Mohammad Gheshlaghi Azar, Zhaohan Daniel Guo, Bilal Piot, Remi Munos, and Michal Valko at Google DeepMind published a groundbreaking paper identifying that DPO is prone to severe over-optimization when trained on noisy or deterministic preference labels.",
    "The root cause of DPO over-optimization lies in the mathematical formulation of the logistic sigmoid loss: -log sigma(beta * (z_w - z_l)). Because the logistic sigmoid function saturates only as its argument approaches positive infinity, the DPO loss can only reach its theoretical minimum of zero by driving the difference between the log-ratios (z_w - z_l) to positive infinity! In attempting to drive the training loss to zero, the optimizer continually pushes the active policy pi_theta further and further away from the reference model pi_ref, until the policy drifts completely outside the trust region, causing catastrophic degradation in general reasoning and conversational capabilities.",
    "To resolve this fundamental vulnerability and establish non-degenerating alignment boundaries, Azar et al. developed Identity Preference Optimization (IPO). Rather than using the saturating logistic loss of Bradley-Terry, IPO formulates preference optimization as a regularized Least-Squares Regression problem with an explicit margin target.",
    "The IPO loss function is defined as: L_{IPO}(theta; pi_ref) = E_{(x, y_w, y_l)} [(log(pi_theta(y_w|x) / pi_ref(y_w|x)) - log(pi_theta(y_l|x) / pi_ref(y_l|x)) - (1 / (2 * tau)))^2], where tau is a regularization parameter that controls the target preference gap.",
    "Notice the transformative mathematical property of the IPO objective: it is a Quadratic Loss function! The minimum of the quadratic loss occurs not at infinity, but when the log-ratio difference exactly matches the finite target margin: z_w - z_l = 1 / (2 * tau). If the active policy drives the margin past this optimal target, the quadratic penalty increases, actively resisting further divergence and preventing the policy from drifting into over-optimized territory!",
    "A centrifugal engine governor analogy illustrates this self-limiting mechanism: in high-speed industrial steam turbines, mechanical flyball governors use centrifugal force to regulate throttle valves. If the turbine spins faster than its safe design limit, the spinning weights fly outward, mechanically throttling the steam intake and keeping rotation speeds strictly within safe operating boundaries. IPO serves as the mathematical flyball governor of preference alignment.",
    "Furthermore, mathematical proofs establish that IPO guarantees bounded generalization error even in the presence of deterministic preference labels or fifty percent label noise, outperforming DPO under real-world data corruption.",
    "In enterprise AI safety governance, deploying IPO ensures that models never sacrifice foundational linguistic capabilities in a desperate quest to minimize alignment loss scores.",
    "Empirical benchmarks confirm that IPO models maintain stable performance across dozens of training epochs without requiring early stopping heuristics or manual learning rate decay.",
    "From a mathematical optimization perspective, the quadratic loss formulation of IPO transforms the preference alignment landscape into a strongly convex bowl around the target margin: even when preference datasets contain severe label noise or completely contradictory annotator ratings, the quadratic penalty exerts a stabilizing restoring force that prevents gradient norms from exploding.",
    "Furthermore, theoretical analysis reveals that the IPO regularization parameter tau provides explicit control over the effective Kullback-Leibler distance between the aligned policy and the reference model: setting tau appropriately guarantees that the policy maintains complete fidelity to foundational pre-trained reasoning abilities while achieving desired behavioral alignment.",
    "In multi-stage enterprise alignment pipelines, deploying IPO as a final stabilization stage following initial DPO or KTO training eliminates latent over-optimization artifacts, producing hardened models ready for mission-critical production deployment.",
    "In summary, Identity Preference Optimization resolves the over-optimization pathology of DPO by introducing quadratic margin regularization, establishing mathematically guaranteed boundaries that prevent policy degeneration."
]

part5_say = [
    "In production enterprise systems, the ultimate engineering aspiration is the creation of Continuous Autonomous Telemetry Alignment Pipelines. Rather than treating AI alignment as an isolated, manual batch campaign conducted once every six months, modern enterprise architectures integrate user feedback directly into streaming continuous learning systems.",
    "In a production customer support or enterprise search platform processing millions of queries daily, user interactions emit a continuous torrent of real-time telemetry events. When an employee clicks 'Copy to Clipboard' on an AI response, that event is tagged as a High-Confidence Desirable Signal (+1). When a user immediately edits a generated SQL query or types 'that is completely incorrect', that interaction is tagged as an Undesirable Failure Signal (-1).",
    "Under legacy PPO or DPO architectures, this continuous stream of unpaired telemetry could not be utilized without expensive human review and pairing. By implementing Kahneman-Tversky Optimization (KTO) combined with Identity Preference Optimization (IPO) regularization boundaries, the enterprise constructs an automated Self-Healing Alignment Engine.",
    "The architecture operates through three pipelined tiers: Telemetry Ingestion and De-Noising, Automated Dynamic Baseline Calibration, and Streaming Asynchronous Policy Fine-Tuning. In Tier One, user interaction events are collected via event streaming proxies (such as Apache Kafka or AWS Kinesis), filtered to strip personally identifiable information (PII), and scored for confidence based on user session tenure and explicit feedback actions.",
    "In Tier Two, incoming feedback events are partitioned into balanced micro-batches, where dynamic reference point estimators update z_ref in real time across domain categories (such as coding, legal analysis, or creative writing). In Tier Three, lightweight LoRA (Low-Rank Adaptation) adapter checkpoints are fine-tuned asynchronously using the KTO-IPO loss objective during off-peak hours.",
    "A municipal smart traffic control analogy illuminates this streaming architecture: in modern smart cities, traffic lights do not rely on static timers programmed months in advance. Instead, optical sensors and underground inductive loops monitor vehicle flow in real time, dynamically adjusting signal phases to clear traffic congestion as it develops. Continuous telemetry alignment dynamically clears cognitive bottlenecks in enterprise AI models as user needs evolve.",
    "Security red-teaming audits confirm that automated telemetry ingestion pipelines incorporate robust outlier detection and adversarial poisoning filters, ensuring that coordinated malicious downvoting campaigns cannot corrupt the model's behavioral posture.",
    "Furthermore, enterprise A/B testing infrastructure automatically routes a small percentage of user traffic to newly aligned adapter checkpoints, tracking live user retention and satisfaction metrics to verify alignment improvements before global deployment.",
    "This autonomous telemetry pipeline represents the pinnacle of modern AI systems engineering: turning everyday user interactions into continuous, self-improving cognitive intelligence.",
    "From a systems infrastructure viewpoint, streaming continuous alignment pipelines operate with high operational resilience: by decoupling event collection, reference estimation, and adapter fine-tuning into independent microservices, the system processes millions of telemetry signals daily without introducing latency into user-facing conversational APIs.",
    "Furthermore, automated telemetry governance frameworks implement differential privacy protocols during feedback aggregation: injecting calibrated mathematical noise into gradient updates prevents adversarial actors from extracting sensitive user prompt contents from fine-tuned adapter weights.",
    "In large-scale enterprise deployments, streaming telemetry alignment creates a compounding competitive advantage: as thousands of employees use the system daily, model accuracy, domain terminology coverage, and stylistic alignment improve automatically, establishing a self-reinforcing cognitive moat.",
    "Hardware scheduling algorithms parallelize asynchronous telemetry micro-batches across idle background workers: while peak daylight hours prioritize interactive user inference, nocturnal cycles trigger automated gradient updates, maximizing round-the-clock compute efficiency without requiring additional cloud resource provisioning across enterprise datacenters.",
    "Furthermore, continuous validation testing guarantees that newly ingested telemetry batches produce monotonic improvements in user task completion rates, certifying operational safety before production deployment.",
    "In summary, combining KTO unpaired optimization with IPO stability boundaries enables autonomous continuous telemetry alignment, establishing the industry blueprint for perpetually self-improving enterprise AI systems."
]

code1 = """function simulateKTOProspectAlignment(desirableCount: number, undesirableCount: number, lossAversionMultiplier: number = 2.1) {
  const utilityGains = desirableCount * 1.0;
  const utilityLosses = undesirableCount * lossAversionMultiplier * -1.0;
  const netProspectValue = utilityGains + utilityLosses;
  const unpairedDataSupport = true;

  return {
    desirableInputs: desirableCount,
    undesirableInputs: undesirableCount,
    kahnemanTverskyLossAversionMultiplier: lossAversionMultiplier,
    netProspectUtility: Number(netProspectValue.toFixed(2)),
    unpairedFeedbackMode: unpairedDataSupport,
    overOptimizationImmunity: "IPO quadratic regularization bounds log-ratio divergence"
  };
}
console.log(simulateKTOProspectAlignment(450, 180));"""

output1 = """{
  desirableInputs: 450,
  undesirableInputs: 180,
  kahnemanTverskyLossAversionMultiplier: 2.1,
  netProspectUtility: 72,
  unpairedFeedbackMode: true,
  overOptimizationImmunity: 'IPO quadratic regularization bounds log-ratio divergence'
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
assert total_words >= 3100, f"Day 48 total word count too low: {total_words}"

day48_dict = {
    "day": 48,
    "title": "Kahneman-Tversky Optimization (KTO) & Identity Preference Optimization (IPO): Unpaired Binary Feedback & Non-Degenerating Over-Optimization Boundaries",
    "goal": "Master Kahneman-Tversky Optimization (KTO) and Identity Preference Optimization (IPO), evaluate the behavioral economics of human loss aversion in AI alignment, understand unpaired binary feedback mechanics, analyze DPO over-optimization vulnerabilities, and engineer quadratic regularization boundaries.",
    "minutes": 38,
    "recap": "Yesterday we mastered Direct Preference Optimization. Today, we conquer KTO and IPO, breaking free from the tyranny of paired comparisons to optimize models on unpaired binary telemetry while guaranteeing non-degenerating optimization boundaries.",
    "parts": [
        {
            "title": "The Operational Friction of Pairwise Preference Annotation",
            "say": part1_say,
            "example": "Website visitors click thumbs up icons rather than comparing dialogues.",
            "code": code1,
            "output": output1,
            "tryIt": "Analyze annotation bottlenecks and evaluate unpaired binary advantages.",
            "check": {
                "question": "What is the primary operational limitation of requiring paired preference data for AI alignment?",
                "options": [
                    "Paired annotation is slow, expensive, and incompatible with real-world unpaired user telemetry like thumbs-up or downvotes.",
                    "Paired annotation can only be performed by quantum computers operating at absolute zero temperatures.",
                    "Paired datasets permanently delete the English language vocabulary from neural network weights.",
                    "Paired comparison requires users to speak their answers into analog telephone lines."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Human users in production applications naturally provide unpaired binary feedback (upvotes/downvotes); forcing paired datasets requires costly manual contrast annotation and ignores massive application logs."
            }
        },
        {
            "title": "Kahneman Tversky Optimization and Human Loss Aversion",
            "say": part2_say,
            "example": "Investors feel the sting of monetary losses twice as acutely as wins.",
            "code": code1,
            "output": output1,
            "tryIt": "Simulate prospect utility functions across binary inputs.",
            "check": {
                "question": "How does Kahneman-Tversky Optimization (KTO) incorporate human loss aversion into its objective function?",
                "options": [
                    "By penalizing undesirable completions more heavily than rewarding desirable completions using asymmetric scaling parameters.",
                    "By randomly deleting negative examples from the training dataset to keep the loss value positive.",
                    "By requiring models to generate monetary currency symbols in every response.",
                    "By doubling the model parameter count whenever an incorrect token is generated."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Grounded in Prospect Theory, KTO configures lambda_U greater than lambda_D, ensuring that harmful or undesirable completions are penalized roughly twice as intensely as equivalent desirable gains."
            }
        },
        {
            "title": "Reference Point Baselines and Unpaired Binary Optimization",
            "say": part3_say,
            "example": "Financial benchmarks measure returns relative to market index averages.",
            "code": code1,
            "output": output1,
            "tryIt": "Calculate implicit reward offsets relative to dynamic reference points.",
            "check": {
                "question": "What is the function of the reference point z_ref in the KTO mathematical formulation?",
                "options": [
                    "It establishes a neutral baseline (expected KL divergence) against which unpaired completions are categorized as gains or losses.",
                    "It converts text tokens into ASCII character codes to reduce graphic memory allocation.",
                    "It prevents the model from generating more than twenty words in any conversational turn.",
                    "It encrypts all prompt embeddings using private key cryptography before backpropagation."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "Because KTO evaluates single unpaired responses, z_ref serves as the neutral baseline course average: completions scoring above z_ref yield positive prospect utility, while those below yield negative loss."
            }
        },
        {
            "title": "Identity Preference Optimization and Bounded Regularization",
            "say": part4_say,
            "example": "Engine governors restrict turbine rotation speeds to prevent burnout.",
            "code": code1,
            "output": output1,
            "tryIt": "Simulate IPO quadratic penalty loss and observe bounded policy margins.",
            "check": {
                "question": "How does Identity Preference Optimization (IPO) resolve the over-optimization pathology of DPO?",
                "options": [
                    "By using a quadratic loss centered on a finite margin target, preventing log-ratios from driving to infinity.",
                    "By removing all negative examples from the dataset and training strictly on supervised demonstrations.",
                    "By freezing all transformer attention heads and training only the bias terms in layer normalization.",
                    "By terminating training after exactly one gradient descent step regardless of dataset size."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "DPO's logistic loss saturates only at infinity, risking policy collapse; IPO introduces a quadratic penalty that reaches its minimum at a finite margin target, bounding policy divergence from reference."
            }
        },
        {
            "title": "Continuous Production Telemetry and Upvote Ingestion",
            "say": part5_say,
            "example": "Adaptive routing engines adjust traffic signals from live road sensors.",
            "code": code1,
            "output": output1,
            "tryIt": "Execute continuous alignment simulation and inspect policy improvements.",
            "check": {
                "question": "What is the primary architectural advantage of combining KTO with streaming production telemetry?",
                "options": [
                    "It allows deployed models to continuously self-improve directly from real-world user interactions without manual pair creation.",
                    "It eliminates the need for computer servers by storing all model weights in local browser cookies.",
                    "It forces all users to submit written essays before accessing the conversational interface.",
                    "It converts all generative text into pre-recorded audio files to avoid GPU inference."
                ],
                "answer": 0,
                "answerIndex": 0,
                "why": "KTO operates directly on unpaired binary signals (upvotes/downvotes), allowing organizations to transform live production telemetry into automated continuous learning pipelines without manual data pairing."
            }
        }
    ],
    "summary": [
        "Analyzed the practical bottlenecks of paired annotation that disconnect alignment research from vast real-world telemetry logs.",
        "Formulated Kahneman-Tversky Optimization (KTO), integrating Nobel Prize-winning Prospect Theory and human loss aversion into alignment objectives.",
        "Dissected dynamic reference point shifting, enabling stable utility evaluation over decoupled positive and negative user interaction events.",
        "Investigated DPO over-optimization vulnerabilities and formulated Identity Preference Optimization (IPO) with quadratic margin regularization.",
        "Architected enterprise continuous telemetry alignment pipelines that ingest real-time user upvotes and downvotes into automated self-healing loops."
    ],
    "projectStep": {
        "title": "KTO Unpaired Prospect Alignment & IPO Regularization Engine",
        "steps": [
            "Construct a KTO prospect utility calculator evaluating asymmetric loss aversion over synthetic unpaired binary telemetry.",
            "Implement an IPO quadratic margin regularizer comparing policy log-ratio divergence boundaries against standard DPO.",
            "Simulate an enterprise streaming telemetry ingestion pipeline updating dynamic reference baselines and fine-tuning LoRA adapters."
        ]
    }
}

captions_data = [
    {
        "say1": "Pairwise preference collection imposes severe operational costs.",
        "say2": "Real world telemetry consists overwhelmingly of unpaired binary signals.",
        "example": "Website visitors click thumbs up icons rather than comparing dialogues.",
        "tryIt": "Analyze annotation bottlenecks and evaluate unpaired binary advantages."
    },
    {
        "say1": "Prospect theory demonstrates that humans exhibit profound loss aversion.",
        "say2": "KTO optimization weights undesirable completions more heavily than gains.",
        "example": "Investors feel the sting of monetary losses twice as acutely as wins.",
        "tryIt": "Simulate prospect utility functions across binary inputs."
    },
    {
        "say1": "Reference point baselines anchor utility evaluations to neutral states.",
        "say2": "Dynamic reference shifts enable stable learning from unpaired binary data.",
        "example": "Financial benchmarks measure returns relative to market index averages.",
        "tryIt": "Calculate implicit reward offsets relative to dynamic reference points."
    },
    {
        "say1": "DPO objectives risk degenerate over optimization on deterministic labels.",
        "say2": "Logistic loss functions push implicit rewards toward extreme values.",
        "example": "Engine governors restrict turbine rotation speeds to prevent burnout.",
        "tryIt": "Simulate IPO quadratic penalty loss and observe bounded policy margins."
    },
    {
        "say1": "Continuous telemetry pipelines ingest live user thumbs directly into KTO.",
        "say2": "Self healing alignment systems adapt dynamically to changing user needs.",
        "example": "Adaptive routing engines adjust traffic signals from live road sensors.",
        "tryIt": "Execute continuous alignment simulation and inspect policy improvements."
    }
]

titles = [
    "The Operational Friction of Pairwise Preference Annotation.",
    "Kahneman Tversky Optimization and Human Loss Aversion.",
    "Reference Point Baselines and Unpaired Binary Optimization.",
    "Identity Preference Optimization and Bounded Regularization.",
    "Continuous Production Telemetry and Upvote Ingestion."
]

columns_list = [
    ["Annotation Pipeline Tier", "Feedback Signal Format", "Operational Throughput Profile"],
    ["Behavioral Economics Layer", "Mathematical Utility Model", "Cognitive Alignment Property"],
    ["Baseline Formulation Tier", "Dynamic Reference Tracking", "Unpaired Optimization Stability"],
    ["Optimization Objective Mode", "Loss Surface Geometry", "Degeneration Protection Bound"],
    ["Production Telemetry Stage", "Streaming Ingestion Flow", "Continuous Learning Capability"]
]

steps_rows = [
    [
        [["Paired Preference Annotation", "Strict Contrast Requirement", "Severe Cognitive Fatigue"], ["Human Contrast Cost", "Prohibitive Vendor Expense", "Low Inter Annotator Agreement"]],
        [["Real World Telemetry", "Natural Unpaired Binary Signals", "Massive Scalable Ingestion"], ["KTO Behavioral Solution", "Decoupled Single Output Loss", "Zero Pair Creation Need"]],
        [["Dual Soda Taste Test", "Slow Artificial Laboratory", "Limited Sample Collection"], ["Supermarket Checkout Logs", "Natural Consumer Purchases", "Millions Of Direct Signals"]],
        [["Synthetic Pairing Hack", "Context Mismatch Artifacts", "Confounding Variable Noise"], ["Native Unpaired Processing", "True Telemetry Compatibility", "Production Grade Scaling"]]
    ],
    [
        [["Classical Economic Utility", "Symmetric Linear Scale", "Flawed Optimization Metric"], ["Kahneman Tversky Prospect", "Empirical Human Psychology", "Asymmetric Loss Aversion"]],
        [["Desirable Completion Value", "Positive Gain Utility", "Modest Satisfaction Boost"], ["Undesirable Blunder Value", "Asymmetric Penalty Multiplier", "Aggressive Trust Protection"]],
        [["Stock Market Profit", "Mild Celebratory Dinner", "Modest Positive Emotion"], ["Severe Monetary Drop", "Visceral Distress And Panic", "Losses Loom Much Larger"]],
        [["Loss Aversion Lambda", "Two Point One Ratio Setting", "Nuanced Enterprise Safety"], ["Heterogeneous Batch Data", "Arbitrary Upvote Downvote Mix", "Robust Convergence Guarantee"]]
    ],
    [
        [["Internal Self Reference", "Paired Contrast Difference", "Inherent Prompt Baseline"], ["Unpaired Solo Evaluation", "Objective Reference Point", "Standardized Outcome Anchor"]],
        [["Dynamic Reference Point", "Expected KL Divergence Average", "Exponential Moving Metric"], ["Positive Outcome Region", "Log Ratio Exceeds Baseline", "Constructive Gradient Ascent"]],
        [["Professional Golf Course", "Standardized Par Baseline", "Individual Course Benchmark"], ["Birdie Score Result", "Below Par Achievement", "Unpaired Global Ranking"]],
        [["Negative Outcome Region", "Log Ratio Below Baseline", "Scaled Loss Aversion Force"], ["Task Modality Invariance", "Balanced Multi Task Scoring", "Zero Gradient Collapse Risk"]]
    ],
    [
        [["Logistic DPO Objective", "Saturating Sigmoid Loss", "Zero Minimum At Infinity"], ["Over Optimization Risk", "Infinite Log Ratio Divergence", "Catastrophic Policy Collapse"]],
        [["Identity Preference IPO", "Quadratic Margin Formulation", "Finite Optimal Target Point"], ["Self Limiting Boundary", "Restoring Resistance Force", "Permanent Reference Anchoring"]],
        [["Centrifugal Engine Governor", "Spinning Flyball Weights", "Mechanical Throttle Control"], ["Excessive Turbine Speed", "Automatic Steam Reduction", "Guaranteed Structural Safety"]],
        [["Deterministic Label Robust", "Fifty Percent Noise Immunity", "Theoretical Bound Guarantee"], ["Multi Epoch Endurance", "Zero Early Stopping Need", "Enterprise Certified Moat"]]
    ],
    [
        [["Manual Six Month Audit", "Stale Static Alignment", "High Latency Adaptation"], ["Continuous Telemetry Stream", "Real Time User Signals", "Perpetual Model Refinement"]],
        [["Explicit User Feedback", "Clipboard Copy And Thumbs", "High Confidence Labels"], ["Streaming Kafka Engine", "Automated PII De Noising", "Zero Manual Review Lag"]],
        [["Smart Municipal Traffic", "Inductive Road Sensors", "Live Adaptive Green Lights"], ["Congestion Cleared Fast", "Real Time Flow Tuning", "Zero Stale Fixed Timers"]],
        [["Off Peak LoRA Adapter", "Asynchronous KTO Update", "Immediate Morning Rollout"], ["Automated A B Gateway", "Live Satisfaction Tracking", "Self Healing Enterprise AI"]]
    ]
]

entries = []
for p_idx, part in enumerate(day48_dict['parts']):
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
    "day": 48,
    "entries": entries
}

# Write lesson JSON to scripts/branch_c
with open("scripts/branch_c/day48_lesson.json", "w", encoding="utf-8") as f:
    json.dump(day48_dict, f, indent=2)

# Write visual envelope
with open("src/lib/data/lessonVisuals/ai/day-48.json", "w", encoding="utf-8") as f:
    json.dump(visual_envelope, f, indent=2)

print(f"Generated Day 48 lesson JSON ({total_words} words) and Visual Envelope successfully!")
