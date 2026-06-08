# BK06 - TongSIM: A General Platform for Simulating Intelligent Machines

## Stable Widened-Core Snapshot

- core_layer: `bridge_core`
- admission_status: `promote_now`
- corpus_tier: `core`
- system_family: `BK06`
- paper_refs: `BK06`
- year: ``
- agent_count: `2-10`
- environment_side_representation: `3D_engine`
- agent_accessible_representation: `L5`
- behavioral_scale: `mixed`
- behavior_type: `dialogue; cooperation; mobility; other`
- evidence_status: `designed_affordance_only`
- spatial_behavior_coupling: `explicit`
- evaluation_method: `mixed`
- space_syntax_construct: `none`
- source_basis: `local_pdf_archived`
- artifact_class: `local_pdf`

## Representation Gap Note

PDF/source review confirms high-fidelity embodied platform, indoor scenes, outdoor town, multi-agent social simulation affordances, and human-AI collaboration; bridge because it is platform-like.

## Original Artifact Pointer

- local_artifact_path: `assets/survey_paper/pdfs/phase1_adjacent/09_BK06_TongSIM.pdf`

## Source Content

Title: TongSIM: A General Platform for Simulating Intelligent Machines

Source PDF: D:\0-AI相关研究\1-spatialagent\spatial-agent\assets\survey_paper\pdfs\phase1_adjacent\09_BK06_TongSIM.pdf

Extraction:
- backend: pypdf
- extracted_at_utc: 2026-04-28T16:33:01+00:00
- page_count: 26
- status: ok
- text_char_count: 86540

Metadata:
- author: Zhe Sun; Kunlun Wu; Chuanjian Fu; Zeming Song; Langyong Shi; Zihe Xue; Bohan Jing; Ying Yang; Xiaomeng Gao; Aijia Li; Tianyu Guo; Huiying Li; Xueyuan Yang; Rongkai Liu; Xinyi He; Yuxi Wang; Yue Li; Mingyuan Liu; Yujie Lu; Hongzhao Xie; Shiyun Zhao; Bo Dai; Wei Wang; Tao Yuan; Song-Chun Zhu; Yujia Peng; Zhenliang Zhang
- doi: unknown
- keywords: unknown
- subject: unknown

Outline:
- Introduction (page 1)
- Related Works (page 2)
  - Simulators for Embodied AI (page 2)
  - Benchmarks for Embodied AI (page 4)
- TongSIM Platform (page 4)
  - Platform Overview (page 4)
  - High Fidelity Scenes (page 6)
  - Customize Tasks and Scenes (page 6)
  - Agent (page 7)
  - Platform Features (page 7)
    - Physical Simulation (page 7)
    - Interactive Objects (page 7)
    - Experimental features (page 8)
    - Parallel Training (page 10)
- Benchmarks (page 11)
  - Single Agent Task: Spatial Exploration and Navigation (page 11)
    - Benchmark Overview (page 11)
    - Baseline (page 11)
    - Metrics (page 11)
    - Experiments and Results (page 12)
  - Multi Agent Task: Multi-Agent Cooperative Search (page 12)
    - Benchmark Overview (page 12)
    - Baseline (page 13)
    - Experiments and Results (page 14)
  - Human-Robot Hybrid Task: Robot Social Navigation (page 14)
    - Benchmark Overview (page 14)
    - Baseline and Metrics (page 15)
    - Experiments and Results (page 16)
  - Primary Composite Tasks: Household Benchmarking Test (page 16)
    - Benchmark Overview (page 16)
    - Test Procedure (page 17)
    - Experiments and Results (page 18)
  - Advanced Composite Tasks: Spatially Situated Social Intelligence Test (page 18)
    - Benchmark Overview (page 18)
    - Baselines and Test Procedure (page 19)
    - Experiments and Results (page 19)
- Discussion (page 20)
  - Various benchmarks (page 20)
  - Potential Applications (page 21)
  - Future Works (page 21)
- Conclusions (page 22)

Markdown Content:

TONGSIM: A GENERALPLATFORM FORSIMULATING
INTELLIGENTMACHINES
Zhe Sun, Kunlun Wu, Chuanjian Fu, Zeming Song, Langyong Shi, Zihe Xue, Bohan Jing,
Ying Yang, Xiaomeng Gao, Aijia Li, Tianyu Guo, Huiying Li, Xueyuan Yang, Rongkai Liu,
Xinyi He, Yuxi Wang, Yue Li, Mingyuan Liu, Yujie Lu, Hongzhao Xie, Shiyun Zhao, Bo Dai,
Wei Wang, Tao Yuan, Song-Chun Zhu, Yujia Peng, Zhenliang Zhang
State Key Laboratory of General Artificial Intelligence, BIGAI, Beijing, China
ABSTRACT
As artificial intelligence (AI) rapidly advances, especially in multimodal large
language models (MLLMs), research focus is shifting from single-modality text
processing to the more complex domains of multimodal and embodied AI. Em-
bodied intelligence focuses on training agents within realistic simulated environ-
ments, leveraging physical interaction and action feedback rather than conven-
tionally labeled datasets. Yet, most existing simulation platforms remain narrowly
designed, each tailored to specific tasks. A versatile, general-purpose training
environment that can support everything from low-level embodied navigation to
high-level composite activities, such as multi-agent social simulation and human-
AI collaboration, remains largely unavailable. To bridge this gap, we introduce
TongSIM, a high-fidelity, general-purpose platform for training and evaluating
embodied agents. TongSIM offers practical advantages by providing over 100
diverse, multi-room indoor scenarios as well as an open-ended, interaction-rich
outdoor town simulation, ensuring broad applicability across research needs. Its
comprehensive evaluation framework and benchmarks enable precise assessment
of agent capabilities, such as perception, cognition, decision-making, human-
robot cooperation, and spatial and social reasoning. With features like customized
scenes, task-adaptive fidelity, diverse agent types, and dynamic environmental
simulation, TongSIM delivers flexibility and scalability for researchers, serving
as a unified platform that accelerates training, evaluation, and advancement to-
ward general embodied intelligence. The source code is publicly available at
https://github.com/bigai-ai/tongsim.
1 INTRODUCTION
The emergence of large language models (LLMs) has revolutionized the understanding of artificial
intelligence (AI). Researchers quickly uncovered a diverse array of capabilities of LLMs within the
text modal, including multi-turn dialogue agents [17, 1, 45], automatic customer services [29, 42],
novel generation and completion [41, 25], text-based automatic non-player characters (NPCs) [5,
57], role-playing [30, 35], and AI-engaged educational systems [6, 10, 11]. As the competence of
LLMs rapidly increases, expectations for these models have begun to shift from purely text-based
applications toward multimodal extensions.
Consequently, a series of research works focused on connecting AI to the real world has emerged
[40, 30, 18, 59]. A particularly prominent area within this trend is Embodied AI. Rather than relying
on conventional labeled data, researchers in this field propose that training agents in high-fidelity
simulated environments and providing them with an embodiment and corresponding action-based
feedback can inject new vitality into AI development [36]. A sufficiently realistic simulation envi-
ronment is crucial to this field. This necessity has spurred the development of a variety of simulation
platforms, such as Interactive Gibson [52] and MINOS [37] that focused on navigation, VRGym [54]
addressing various human interfaces for multimodal interaction, and platforms dedicated to indoor
household tasks [44, 21, 33]. While some simulation platforms primarily support only one or a
1
arXiv:2512.20206v1  [cs.AI]  23 Dec 2025

Figure 1: TongSIM, a simulation platform for general-purpose embodied AI agent training and
evaluation. We provide diverse high-fidelity indoor and outdoor scenes that suit a large range of
tasks, as well as multiple embodiments, including not only human-like figures but also robotic ones.
few categories of embodied AI tasks, the scope of supported task types is observably increasing
[49, 34, 23].
Against this backdrop, a general-purpose simulation platform that can support both low-level tasks,
such as embodied robot training, and high-level tasks, such as single-agent and even multi-agent
social simulations, is essential. Such a platform can provide a highly consistent embodied general-
purpose agent training environment, facilitating researchers from different fields to conduct model
training, testing, and even develop new tasks on the same platform, which will help advance the
development of general-purpose embodied intelligence.
In this work, we presentTongSIM, a high-fidelity, universal embodied intelligence training and
testing platform that supports complex indoor and outdoor scene simulation, as shown in Figure 1.
In this platform, we have constructed a diverse range of indoor and outdoor scenes. Leveraging
these diverse and rich scenes, we have proposed a series of benchmarks. These benchmarks cover
a wide range of agent capabilities, including perception, cognition, decision-making, human-robot
cooperation, spatial and social understanding, covering both low-level tasks (such as navigation)
and high-abstraction tasks (such as multi-agent games), forming a comprehensive evaluation system
that spans the entire spectrum [31]. Users can independently select different benchmarks to train or
test specialized agents or integrate these benchmarks for general-purpose agents. Specifically, we
propose 5 categories of benchmarking tasks, including single-agent tasks, multi-agent tasks, human-
robot interaction tasks, primary family composite tasks, and advanced family composite tasks.
2 RELATEDWORKS
Progress in Embodied AI is inextricably tied to developments in simulation technologies and eval-
uation benchmarks. High-fidelity simulation environments offer low-cost, safe, and reproducible
training platforms for agents, while diverse benchmarks drive the evolution of these agents from
foundational visual navigation to complex, long-horizon task execution.
2.1 SIMULATORS FOREMBODIEDAI
The evolution of simulation platforms outlines a clear technical trajectory: transitioning from static,
visually faithful environments designed for navigation, to physics-rich interactive worlds support-
2

Table 1: Comparison of embodied AI simulators. We compare TongSIM (Ours) with state-of-
the-art platforms across simulation engines, asset diversity, platform features, and supported tasks.
TongSIM possesses the common features of current state-of-the-art simulators, and it stands out in
city-level interaction, task-oriented fidelity, and the variety of the supported tasks.
Features TongSIMGRUtopiaOmniGibsonHabitatVirtualHomeVirtual Community(Ours) [49] [24] [34] [32] [63]
Core Engine Base UE 5 Isaac Sim Isaac Sim Bullet Unity3D Genesis
Environment& Scenes
Scene 115 100 Annotated 50 211 6 35 Urban AreasIndoor Scope ✓ ✓ ✓ ✓ ✓ ✓Outdoor Scope ✓ ✓ ✓ ✗ ✗ ✓City-level Interaction✓ ✓ ✗ ✗ ✗ ✓
PlatformFeatures
Parallel Training ✓ ✓ ✓ ✓ ✗ ✗Task-oriented fidelity✓ ✗ ✗ ✗ ✗ ✗NPC Control ✓ ✓ ✗ ✓ ✓ ✓Sim-to-Real Support ✓ ✓ ✓ ✓ ✗ ✓
SupportedTasks
Single-Agent ✓ ✓ ✓ ✓ ✓ ✓Multi-Agent ✓ ✓ ✗ ✓ ✓ ✓Human-Robot Teaming✓ ✗ ✗ ✓ ✗ ✓
ing fine-grained manipulation, and currently advancing towards generative, open-ended ecosystems
powered by AI, aiming to reconcile the trade-off between training scalability and physical realism.
The Habitat platform [38] epitomizes high-efficiency and large-scale simulation. Comprising the
high-performance 3D simulator Habitat-Sim and the embodied reinforcement learning (RL) frame-
work Habitat-Lab, its core advantage lies in extreme rendering throughput. Capable of running in
parallel at thousands of frames per second, it significantly accelerates the training cycle of RL al-
gorithms. Early iterations, primarily utilizing real-world 3D scan datasets (e.g., Matterport3D[9]),
focused on visual fidelity to support visual navigation tasks. With the release of Habitat 2.0 [46],
the platform integrated the Bullet physics engine, extending capabilities to interactive navigation.
Most recently, Habitat 3.0 [34] introduced humanoid avatars, establishing “Co-Habitat” scenarios
for human-robot-environment coexistence, marking a shift towards social interaction capabilities.
Sharing this focus on human-centric environments, VirtualHome [32] utilizes Unity3D to abstract
household activities into executable programs, specifically targeting action understanding and high-
level task planning.
Unlike Habitat’s emphasis on scene scale, SAPIEN [53] and iGibson 2.0 [23] prioritize interaction
precision at the object level. SAPIEN focuses on manipulation tasks involving articulated objects,
utilizing physics-driven active stereoscopic vision simulation to bridge the visual Sim-to-Real gap.
iGibson 2.0 [23], an open-source environment built on the PyBullet physics engine, emphasizes
object-centric simulation. It supports various long-horizon household tasks, such as cleaning and
cooking, and introduces an evaluation system based on logical states.
To further narrow the Sim-to-Real domain gap, some simulators have adopted GPU-accelerated
physics engines and ray-tracing technologies. NVIDIA’s Isaac Sim [28], built on the Omniverse
platform, leverages the PhysX 5 engine to provide high-fidelity physics simulation and integrates
real-time ray tracing. It is widely applied in industrial robot manipulation and Sim-to-Real transfer
research. As the successor to iGibson [23], OmniGibson [24] has also migrated to the Omniverse
architecture. Utilizing the PhysX backend, it achieves real-time simulation of complex materials
such as fluids and cloth, accommodating large-scale benchmarks like BEHA VIOR-1K [24].
Furthermore, the field is evolving towards generative simulation. Genesis [4] acts as a nascent
universal physics engine, unifying simulation frameworks for rigid bodies, fluids, and soft bodies,
while exploring the use of generative AI to construct 4D dynamic worlds. Building upon this gener-
ative capability, Virtual Community [63] expands the simulation horizon from single households to
city-level ecosystems. It leverages a generative pipeline to construct diverse urban districts, support-
ing complex physical and social planning tasks that require agents to navigate and interact within
metropolitan contexts. Concurrently, ProcTHOR [15] employs procedural generation to automati-
cally construct massive environments, offering an effective solution to the scarcity of scene data for
training. We compared the features of TongSIM and several state-of-the-art simulators in Table 1.
Currently, simulation technology still faces a trade-off between runtime efficiency and physical fi-
delity: platforms pursuing extreme speed (e.g., Habitat [38, 46, 34]) often simplify contact dynam-
3

ics, whereas those prioritizing high-fidelity physics (e.g., Isaac Sim [28], OmniGibson [24]) incur
significantly higher computational costs. Constructing a unified architecture that balances large-
scale parallel training with high-precision physical interaction remains a core engineering challenge
in the field.
2.2 BENCHMARKS FOREMBODIEDAI
Benchmarks in Embodied AI reflect the trajectory of task complexity: evolving from instruction
following and navigation to object manipulation in household settings, and finally to general task
planning in open worlds.
Early benchmarks primarily focused on an agent’s spatial understanding of natural language in-
structions. Room-to-Room (R2R) [2] is a seminal work in Vision-and-Language Navigation (VLN),
requiring agents to plan paths in real-world scanned indoor environments based on linguistic in-
structions. Although R2R [2] propelled the development of multimodal models, the simplicity of
its action space and task state transitions limited its utility for evaluating complex embodied intelli-
gence.
ALFRED [43] elevated the challenge to long-horizon, compositional household manipulation tasks
(e.g., “rinse a mug and place it in the coffee maker”). ALFRED’s core contribution lies in intro-
ducing irreversible state changes and long action sequences, rigorously testing an agent’s long-term
memory, task decomposition, and planning capabilities. This benchmark shifted the research fo-
cus from pure navigation to scenarios requiring fine-grained object manipulation, often grounded in
interactive environments like AI2-THOR [22].
Pursuing the goal of artificial general intelligence (AGI), subsequent benchmarks have sought
greater scale and behavioral diversity. BEHA VIOR-1K [24] represents a significant step toward
training generalist agents. Containing 1,000 everyday human activities, it emphasizes human-centric
behaviors and realistic simulation, aiming to foster capabilities for diverse, open-ended tasks. Re-
garding environment scale, ProcTHOR [15] utilizes procedural generation to break the constraints
of limited real-world scans, enabling the rapid creation of massive embodied AI environments. Af-
ter constructing simulation environments, the next step is to deploy tasks, which can be used for
both evaluation and training. Recent research has increasingly emphasized dynamic task genera-
tion, rather than relying on traditionally manually collected tasks [16, 12, 13]. However, most task
generation approaches are designed for highly structured domains, such as code-based tasks [61],
GUI-based tasks [7], or game-based tasks [62, 47]. Existing task generation approaches for em-
bodied 3D simulation environments are largely limited to low-level variations, such as modifying
scenes, objects, or spatial layouts [15, 50].
Recent research explores ultra-long-horizon planning and larger-scale environments. CookBench
[8] focuses on complex cooking scenarios, requiring intent recognition and fine-grained interaction
over long sequences, posing severe challenges to the reasoning capabilities of LLMs and vision-
language models (VLMs). GRUtopia [49] signifies a migration from indoor to city-scale environ-
ments, aiming to explore Scaling Laws in Embodied AI and providing the first simulation platform
for general-purpose robots in complex, socialized urban scenarios.
These complex benchmarks collectively reveal a critical challenge: error accumulation in long-
horizon planning. In tasks like CookBench, minor deviations in early actions can be amplified
exponentially in subsequent steps, leading to task failure. Consequently, research into Embodied
World Models is becoming increasingly vital, with the core challenge being the maintenance of
temporal consistency and the mitigation of error accumulation. The evaluation paradigm is also
shifting, moving beyond simple task success rates to quantifying an agent’s capacity for physical
consistency, state understanding, and counterfactual reasoning.
3 TONGSIM PLATFORM
3.1 PLATFORMOVERVIEW
TongSIM is designed as a comprehensive and versatile simulation platform for general intelligent
machines. Built upon Unreal Engine 5.6 (UE5.6), the platform extends the native capabilities of
4

Software
Multimodal data sensor
Functional Features Various Tasks
Evaluation System
Large-scale NPC system Parallel training
High-fidelity simulation
 Indoor navigation Multi-agent cooperation
Home composite tasks Situated social reasoning
Level of intelligence
Infrastructure Support Task Dara
Env.
Value
Vision
Learning
Motor
Language
Cognition
Figure 2: Overview of the TongSIM system architecture. The platform contains a unreal engine-
based simulator and a python controller which can communicate with the simulator. Within the
simulator, four features are supported, including multimodal data sensors, high-fidelity simulation,
large-scale NPC systems, and parallel training. Based on this platform, various tasks are developed
to support embodied AI, such as indoor navigation, multi-agent cooperation, home composite tasks,
etc. Also, the platform integrates the evaluation system to evaluate the performance of agents about
tasks, abilities, and level of intelligence.
the engine through a suite of custom-developed wrappers and interfaces. These extensions facilitate
robust communication, debugging, and control, effectively managing high-dimensional simulation
data—including scene semantics, object states, and agent metadata—to streamline agent training,
testing, and secondary development.
Specifically, the TongSIM platform comprises 115 distinct simulation scenarios, designed to support
a diverse array of tasks. These environments are populated with thousands of high-fidelity objects.
To emulate realistic anthropomorphic behavioral patterns, we implemented 28 distinct interaction
functions to satisfy the interaction requirements of both embodied agents and human users.
TongSIM provides rich semantic annotations to support learning tasks. We assign category labels
to common objects, facilitating efficient filtering and supervised training. To support rule-based
autonomous navigation for virtual humans and robots, we have baked navigation meshes into both
indoor and outdoor environments. Furthermore, each environment is equipped with a Scene Man-
ager, which provides users with ground-truth data, including scene metadata, segmentation maps,
spawn points, and navigation information. All provided assets support custom secondary annotation,
allowing researchers to tailor data to specific requirements.
The system architecture of TongSIM is illustrated in Figure 2. To facilitate the integration of diverse
agents and models, TongSIM provides a comprehensive application programming interfaces (APIs)
of Python. This enables developers to exert granular control over the simulation environment and
embodied agents via Python scripts. Key functionalities include: level management (loading/un-
loading), dynamic instantiation of objects and avatars, character manipulation, state retrieval, cam-
era control, retrieval of objects near specific coordinates, and the execution of native UE console
commands.
A typical operational workflow commences with the initialization of the TongSIM UE Server, fol-
lowed by the deployment of a TongSIM UE Client to establish a connection. Utilizing the Python
software development kit (SDK), users manipulate scenes, objects, NPCs, and agents, while the
resulting visual states are rendered and streamed to a web interface for observation by both human
operators and agents. Simultaneously, the TongSIM-Audio2Face module synthesizes and synchro-
nizes facial expressions and vocalizations for NPCs and agents. Furthermore, the platform supports
immersive interaction via virtual reality (VR) devices, requiring the execution of a dedicated VR
Client to interface with the server.
5

Figure 3: Statistics of indoor environments in TongSIM. The dataset spans diverse functional cat-
egories (e.g., residential, commercial) and architectural styles (e.g., modern, classical Chinese),
designed to support complex, human-centric tasks.
3.2 HIGHFIDELITYSCENES
To support comprehensive and general-purpose agent training and testing, the TongSIM platform
offers a vast and diverse collection of simulation environments featuring varying levels of fidelity.
Specifically, this comprises 115 indoor environments and extends support to urban-scale outdoor
scenarios.
Regarding indoor settings, a defining characteristic of TongSIM is its capacity to support complex
hybrid daily living tasks. To ensure semantic realism, we engaged professional designers to manu-
ally curate spatial layouts and furniture arrangements, thereby guaranteeing that these environments
strictly adhere to anthropomorphic behavioral logic. Building upon these expert-designed environ-
ments, we developed an automated expansion pipeline that scales the repository to a total of 115
distinct scenes. Functionally, these environments cover diverse categories such as residential units,
cafes, and retail stores. Stylistically, they span a wide architectural spectrum, ranging from mod-
ern apartments and villas to medieval castles, traditional Japanese gardens, and classical Chinese
architecture. Detailed statistics regarding the indoor scenes are presented in Figure 3.
Regarding outdoor scenarios, rather than assembling isolated environmental fragments, we have
constructed a holistic virtual metropolis, as illustrated in Figure 4. This unified world encompasses
diverse functional zones, including educational institutions, residential complexes, commercial dis-
tricts, and medical facilities, along with a comprehensive road network and a dynamic traffic simula-
tion system. Crucially, these functional zones are spatially contiguous. This design enables embod-
ied agents to navigate seamlessly across distinct regions, thereby preserving contextual continuity
during long-horizon training and evaluation tasks.
3.3 CUSTOMIZETASKS ANDSCENES
To enhance the scalability and diversity of the TongSIM environment, we developed an automated
procedural generation pipeline capable of expanding the scene repository based on existing assets.
This method follows a coarse-to-fine strategy. In the coarse-grained phase, we decompose existing
indoor scenes into independent functional units (e.g., bedroom, study, kitchen). These units are then
stochastically recombined to synthesize novel layout configurations, where the door frames serve
as alignment anchors. In the fine-grained phase, we introduce micro-level variations to the interior.
Specifically, we apply random perturbations to the poses of movable objects and randomly replace a
subset of assets with the same-category counterparts retrieved from our object library. This process
significantly enriches the diversity of interior decor, spatial layouts, and object appearances. Finally,
to guarantee the high fidelity of the TongSIM platform, we employ a human-in-the-loop validation
step where professional designers filter and fine-tune the generated scenes, pruning any instances
that exhibit semantic implausibility.
Complementing the automated generation pipeline, TongSIM features a robust external content im-
port framework. This framework is designed for high compatibility with mainstream digital con-
6

Figure 4: Visualization of the TongSIM Outdoor World. The platform simulates a holistic, spatially
contiguous urban environment rather than isolated fragments.
tent creation (DCC), computer-aided design (CAD), and 3D scanning workflows, allowing exist-
ing assets to be seamlessly integrated into the platform’s simulation tasks and evaluation pipelines.
Through a minimal preprocessing procedure, including comprising unit standardization, coordinate
system alignment, and lighting configuration, users can efficiently import custom environments or
third-party assets. Currently, TongSIM supports formats including glTF 2.0 (.gltf/.glb), FBX Scene,
and Datasmith (.udatasmith), comprehensively covering industry-standard 3D data representations.
3.4 AGENT
TongSIM provides diverse agents that can serve both as embodiments for AI models during training
and evaluation, and as NPCs to facilitate task execution and enhance environmental fidelity. To
govern the behaviors of these NPCs, TongSIM implements a hybrid automatic control mechanism
driven by rule-based logic and LLMs.
TongSIM equips these agents with versatile functional capabilities and diverse visual appearances,
allowing external AI models to drive embodiments via a Python API. The supported action space
spans multiple levels of complexity, including kinematic primitives (e.g., nodding, waving, turning),
target-driven behaviors directed at specific coordinates or objects (e.g., gazing, point-to-point navi-
gation), and fundamental object interactions (e.g., pick-and-place, toggling doors, sitting/standing).
Furthermore, the platform supports complex composite activities that involve multi-step sequenc-
ing and high-level semantics, such as consuming items, pouring liquids, mopping, wiping surfaces,
reading, cutting food, and simulating daily routines like sleeping or washing.
3.5 PLATFORMFEATURES
3.5.1 PHYSICALSIMULATION
The platform leverages the built-in Chaos physics engine of Unreal Engine 5 to achieve rigid
body dynamics, fluid simulation, destruction, cloth, etc. This feature makes TongSIM suitable
for constructing relative complicated 3D scenes, which supports the testing for embodied AI like
robots. Meanwhile, we also try to integrate another physics simulation library (NVIDIA Flex) into
TongSIM, which uses a unified particle to represent all object types, allowing different simulation
materials to seamlessly interact.
3.5.2 INTERACTIVEOBJECTS
The platform constructs a protocol-based interaction system, achieving granular control over simu-
lation entities through core protocols such as interactable ability. The platform supports 28 distinct
7

Figure 5: Statistics of the objects in TongSIM. The dataset spans diverse functional categories (e.g.,
residential, commercial) and architectural styles (e.g., modern, classical Chinese), designed to sup-
port complex, human-centric tasks.
interaction primitives and provides thousands of interactable objects. The statistics of some of the
objects in TongSIM are shown in Figure 5. This system not only covers basic operations, such
as entity lifecycle management (generation, destruction) and geometric transformations (rotation,
scaling), but also implements deep simulation of electromechanical logic and spatial semantic.
Electromechanical Logic.The system employs a dual-layer control mechanism that decouples the
“powered state” from the “activation state” to accurately simulate the operational principles of real-
world devices. The final operational state of a device is jointly determined by its physical power
supply and switch control status; consequently, if an entity lacks a power connection, it remains
non-functional even if logically activated. This design faithfully reproduces the physical dependency
between electrical connectivity and device manipulation.
Spatial Interaction Anchors.To address the challenges of fine-grained manipulation in complex
environments, the platform defines semantically annotated spatial interaction anchors. These an-
chors guide end-effectors (e.g., hands, robotic arms) to precisely target the coordinates of functional
zones, such as handles or buttons, thereby establishing robust connection constraints. Furthermore,
to facilitate composite interactions involving multi-object synergy, where task completion relies on
specific spatial coordination between entities, the system introduces the concept of Placement Points.
These points serve as predefined spatial docking slots that automatically calibrate the relative align-
ment between objects, such as aligning a cup beneath a water dispenser.
3.5.3 EXPERIMENTAL FEATURES
Automatic Procedural Actions.This module provides animation-asset-free, procedural locomo-
tion and arm articulation capabilities for humanoid agents within the TongSIM platform. An ex-
ample is shown in Figure 6. Leveraging Control Rig and Inverse Kinematics (IK), the system syn-
thesizes naturalistic gaits in real-time, adapting seamlessly to diverse skeletal structures and pro-
portions. It is designed for real-time, large-scale interactive scenarios. In TongSIM, procedural
animation serves as a unified foundational locomotion layer, deeply integrated with the platform’s
task, navigation, physics, and perception pipelines. By supporting parameterization and controllable
stochasticity, the module ensures stability across diverse scenes, allowing users to rapidly deploy
agents across arbitrary environments and benchmark tasks without modifying skeletal assets.
Text-Driven Motion Generation.This module implements a diffusion-based motion generation
model that synthesizes playable character animation sequences in real-time, utilizing textual intent
and environmental voxel maps as inputs. A typical procedure is shown in Figure 7. The system
features the following core capabilities. (1) Text-driven control (natural language + target context):
The system encapsulates natural language expressions alongside target positions and interaction ob-
jects within instructions. These are unified and parsed into executable intents and constraints for
8

Figure 6: In TongSIM, programmatic animation functions, as a unified fundamental motion layer,
are integrated with the platform’s task, navigation, physics, and perception pipelines. Programmatic
animation supports parameterization and controllable randomness, maintaining stability across dif-
ferent scenes. Users can rapidly deploy it in any scene and benchmark task without needing to
modify the skeleton assets.
Figure 7: A typical procedure of text-driven motion generation.
the model. (2) Environmental perception (voxelized geometric semantics): The system performs
real-time sampling of voxel grids around the character’s current position and the first two trajectory
waypoints. This constructs spatial semantics representing navigable areas and obstacles to facilitate
model planning and collision avoidance. (3) Segmented generation and streaming playback: Lever-
aging a bi-directional gRPC streaming pipeline, the system implements a “generate-while-playing”
mechanism. This ensures seamless concatenation and automatic continuation of subsequent se-
quences, achieving low-latency real-time generation. (4) V oxel generation engine: This component
provides comprehensive environmental voxel encoding. It constructs a voxel volume around the first
two path waypoints, performs parallel sampling of geometric occupancy, and generates a bitmap
byte stream transmitted with the request. (5) Controllable root motion fusion: The server dictates
the rhythm of vertical motion (e.g., undulation and footfall timing), while horizontal displacement
and steering are dynamically planned by local navigation and control modules.
Large-Scale Crowd Simulation.To support human-robot hybrid tasks (e.g., social navigation,
collaborative guidance, and interactive behavior learning), as shown in Figure 8, we constructed a
hierarchical crowd simulation module designed to simultaneously achieve individual-level physi-
cal fidelity and group-level behavioral diversity. (1) Low-level motion control: Social force model
(SFM) and A*-based feasible region sampling. The foundational layer employs the social force
model, introducing force-based interpersonal interactions and environmental constraints to realize
natural obstacle avoidance and aggregation behaviors in local space. (2) High-level decision making
and planning: At the high-level decision layer, the system incorporates VLMs to simulate the seman-
tic behaviors of human agents and support interaction and collaboration with robotic agents. This
9

Figure 8: Simulation of diverse crowd and pedestrian movement patterns.
(a)
 (b)
Figure 9: Parallel training. (a) Visualization of 48 Parallel Environments. (b) The steps per Second
varies as the number of parallel environments.
mechanism endows crowd simulation with semantic controllability and task relevance, achieving
semantic alignment and intelligent synergy with the robot’s task planning modules.
From Simulation to Reality.To facilitate realistic robotic tasks and bridge the Simulation-to-
Reality (Sim-to-Real) gap, we have explored two experimental integration strategies. The first strat-
egy involves replacing the native UE5 physics engine with the open-source MuJoCo engine [48].
In this configuration, the physical simulation of all scene entities is delegated to MuJoCo, and the
resulting state updates are synchronized with UE5’s rendering pipeline for visual output. This ap-
proach integrates MuJoCo’s superior physical fidelity and robust robotic training capabilities into
TongSIM, effectively compensating for the limitations of UE5’s native dynamics simulation. The
second strategy introduces native support for Isaac Lab, migrating both the physics and rendering
engines to Isaac Sim. Crucially, this integration preserves TongSIM’s established task architecture
and agent interfaces. This design facilitates seamless alignment with the robotics community, allow-
ing for the reuse of extensive toolchains within the robotics research ecosystem. Both approaches
are currently in the experimental phase, aiming to extend TongSIM’s compatibility to a broader
spectrum of agent types and achieve a unified simulation framework for diverse embodiments.
3.5.4 PARALLELTRAINING
To accommodate the demands for efficient agent training and optimize data sampling efficiency in
RL, TongSIM introduces a multi-environment parallel execution mechanism. By simultaneously
loading multiple mutually independent sub-levels within a single UE instance, this mechanism en-
ables agents to concurrently acquire interaction data from diverse environments at each time step,
thereby significantly amplifying sample generation throughput.
10

To evaluate the performance of this mechanism, we utilized the “spatial exploration and navigation”
task (see Subsect. 4.1) as a benchmark. Experiments were conducted on a personal workstation
equipped with an Intel Core i9-13900KF CPU (24 cores/32 threads, 3.00 GHz) and an NVIDIA
GeForce RTX 4090 GPU. Experimental results demonstrate that, compared to single-environment
sequential execution, the parallel setting achieves a substantial increase regarding the interaction
throughput measured in steps per second. Specifically, the sampling rate exhibits near-linear scaling
as the number of parallel environments increases, as shown in Figure 9 (b). However, at higher
degrees of parallelism, performance gains gradually saturate due to overhead associated with inter-
process communication and system scheduling.
TongSIM’s parallel execution mechanism effectively enhances sample acquisition efficiency and
minimizes training time costs, establishing a robust foundation for large-scale reinforcement learn-
ing in complex simulation environments.
4 BENCHMARKS
4.1 SINGLEAGENTTASK: SPATIALEXPLORATION ANDNAVIGATION
4.1.1 BENCHMARKOVERVIEW
Autonomous exploration and navigation represent critical pillars for intelligent agents operating in
partially observable physical environments. Effective exploration demands that an agent maximize
coverage of the state space, converting unknown areas into semantic maps to locate targets of in-
terest. Subsequently, navigation entails executing optimal paths to reach these identified locations
while negotiating obstacles. To rigorously evaluate these competencies, we introduce the spatial
exploration and navigation test, a benchmark specifically designed to assess the exploration and
navigation performance of intelligent agents.
The benchmark centers on a challenging cleanup task,as illustrated in Figure 10, requiring the agent
to navigate complex, multi-room indoor environments cluttered with obstacles to collect scattered
paper balls. To foster diversity, the quantity and spatial distribution of the targets, as well as the
agent’s initialization pose, are fully randomized. Crucially, to guarantee task feasibility, we pre-
calculate the traversable free space based on the agent’s collision geometry and environmental ob-
stacles, ensuring that both the agent and all targets are strictly spawned within reachable regions. The
environment provides a rich observation space comprising egocentric RGB images, depth maps, and
voxel grids. Correspondingly, the agent utilizes an action space designed for navigation, enabling
movement to specific coordinates and rotation toward target orientations.
4.1.2 BASELINE
In this benchmark, we project the volumetric voxel data of the task space onto a 2D plane to generate
an occupancy grid. Specifically, we extract an egocentric19×19local grid, corresponding to
a physical area of208cm×208cm, to serve as the agent’s observation. To establish a robust
baseline for comparison, we train a policy using proximal policy optimization (PPO) algorithm [39].
Furthermore, we incorporate human trials into the evaluation framework to quantify the performance
gap between the autonomous agent and human operators.
4.1.3 METRICS
We employ two primary metrics to evaluate agent performance:success rate (SR)andefficiency.
The success rate measures the ratio of episodes where the agent successfully explores the entire
task space and eliminates all scattered debris within a predefined maximum number of steps (Tmax).
The efficiency quantifies the agent’s temporal performance based on step consumption. Since fewer
steps indicate superior performance, we formulate efficiency as a normalized score relative to the
maximum allowable steps. The success rate is calculated as follows:
SR= Nsuccess
Ntotal
×100%(1)
11

Figure 10: An exemplary scenario of the paper ball cleaning task. The environment consists of
multiple rooms, each furnished with various items, with paper balls scattered randomly across the
floor. The agent under test is spawned at a random location within one of the rooms. It is required
to explore these rooms to clean up all the paper balls.
whereN total represents the total number of evaluation episodes, andN success denotes the number of
successful episodes. The efficiency is defined as:
Efficiency= 1
Nsuccess
NsuccessX
i=1
 Tmax −S i
Tmax

(2)
whereN success is the count of successful episodes,T max represents the maximum number of steps
allowed per episode, andS i denotes the number of steps taken by the agent to complete thei-th
successful episode.
4.1.4 EXPERIMENTS ANDRESULTS
Table 2: Performance comparison between Human and RL Agent (PPO) on the benchmark.
Agent Success Rate Efficiency
PPO 0.6 0.34
Human 1.0 0.54
Using the proposed benchmark, we evaluated both the RL baseline model (PPO) and human oper-
ators. The comparative results are presented in Table 2. Quantitative analysis reveals that the RL
agent achieves a success rate of only 60%. While the agent demonstrates the capability to complete
the cleanup task to a certain extent, its performance significantly lags behind the human baseline in
both success rate and efficiency.
To investigate the underlying causes of the agent’s suboptimal performance, we conducted a qual-
itative analysis of the failure cases. We identified two primary limitations as follows. (1) Obsta-
cle avoidance in cluttered environments: The RL agent frequently collides with obstacles or be-
comes trapped within narrow, obstacle-dense regions, indicating a deficiency in fine-grained colli-
sion avoidance capabilities. (2) Long-horizon navigation: The agent exhibits difficulty in traversing
between distinct rooms, highlighting limitations in its spatial planning and long-horizon navigational
reasoning.
4.2 MULTIAGENTTASK: MULTI-AGENTCOOPERATIVESEARCH
4.2.1 BENCHMARKOVERVIEW
To facilitate research on multi-agent collaboration in complex 3D environments, we introduce the
multi-agent cooperative search (MACS) task. Built upon the TongSIM platform, the task simulates
a partially observable post-flood search scenario characterized by stochastic dynamic hazards and
12

(a)
 (b)
Figure 11: Visualization of the multi-agent cooperative search (MACS) task scenarios. (a) Detailed
scenario view. Key entities are explicitly labeled: agents, target supplies requiring collaborative
collection, and dynamic hazards that must be proactively evaded. The green lines emanating from
the agents provide a visualization of the radial ray-casting sensor array, illustrating the localized
perception mechanism under conditions of partial observability. (b) Parallel training array: The
top view of3×3array showing concurrent execution environments utilized for scalable multi-
agent training. The blue dotted circumferences delineate the maximum sensory detection range for
individual agents within the complex environment.
static obstacles, as shown in Figure 11. The core challenge lies in evaluating the agents’ ability to
achieve the following objectives under conditions of partial observability:
•Collaboration:Agents must collaborate to collect supplies that require multi-agent ma-
nipulation.
•Safety Constraints:Agents are required to proactively identify and evade hazardous ma-
terials moving randomly within the environment.
•Efficient Navigation:Relying solely on local sensory data, agents must plan energy-
efficient, optimal paths through complex, dynamic environments.
Fundamentally, MACS serves as a robust experimental platform for the training and evaluation
of state-of-the-art multi-agent reinforcement learning (MARL) algorithms. Technically, the envi-
ronment is formulated with a continuous 2-dimensional action space (Box(−1.0,1.0)) governing
agents’ movements, and a high-dimensional observation space constructed from a radial array of
sensors that capture the relative distance, orientation, and velocity of surrounding entities. Further-
more, to accommodate diverse experimental requirements, the environment features high configura-
bility. The key parameters and their default settings are detailed in Table 3.
4.2.2 BASELINE
To validate the efficacy of the proposed benchmark and establish a reference for future research,
we evaluate two representative MARL algorithms. These baselines span from fully decentralized
approaches to centralized training paradigms. (1) Independent PPO (IPPO) [14]: A fully decentral-
ized algorithm where each agent learns an independent policy based solely on its local observation,
ignoring the joint state information. (2) Multi-Agent PPO (MAPPO) [56]: A widely-adopted algo-
rithm following the centralized training with decentralized execution (CTDE) paradigm. It utilizes
a centralized value function to exploit global state information during training while maintaining
decentralized policies during execution.
We train and evaluate these baselines under the standard environment configuration (default values
provided in Table 3). We employ the mean episodic return per agent ( ¯R) as our primary metric,
defined as the total team reward normalized by the agent populationN. Formally:
¯R= 1
N
NX
i=1
TX
t=1
r(i)
t (3)
13

Table 3: Detailed environment specifications and default hyperparameters for the MACS Task.
Parameter Description Default
n agentsNumber of rescue agents 5
n suppliesNumber of valuable supply items 10
n hazardsNumber of hazard items 10
n coopAgents required for successful cooperation 2
n sensorsNumber of sensors per agent 30
sensor rangeMaximum sensing range 500.0
max cyclesMaximum steps per episode 500
supply rewardReward for successfully collecting supplies 10.0
hazard rewardPenalty for encountering hazards−1.0
encounter rewardReward for touching a supply without capture 0.01
thrust penaltyEnergy cost multiplier per movement step−0.01
local ratioRatio of local rewards to global rewards 0.9
Table 4: Performance comparison of baseline algorithms on the MACS Task. Results are averaged
over evaluation episodes.
Method Mean Step Reward Mean Episodic Return per Agent
MAPPO (CTDE)0.0380 19.24
IPPO (Independent) 0.0295 14.75
Random -0.013 -6.51
wherer (i)
t denotes the reward received by agentiat time stept, andTrepresents the episode horizon.
We additionally report the mean step return, calculated as ¯R/T, which quantifies the average reward
density per time step.
4.2.3 EXPERIMENTS ANDRESULTS
Table 4 presents the comparative performance of the baseline algorithms. Empirical results demon-
strate that the centralized training approach significantly outperforms the fully decentralized method.
MAPPO achieves the highest mean episodic return per agent of 19.24, whereas IPPO yields 14.75.
This performance gap indicates that the CTDE paradigm effectively leverages global information to
coordinate agents in complex search tasks. Both learning-based methods significantly surpass the
Random policy baseline.
4.3 HUMAN-ROBOTHYBRIDTASK: ROBOTSOCIALNAVIGATION
4.3.1 BENCHMARKOVERVIEW
Autonomous robots represent the quintessential manifestation of embodied intelligence within the
physical world. In the era of human-robot symbiosis, achieving safe and efficient human-centric
interaction within large-scale, dynamic, and unstructured environments has emerged as a pivotal
scientific challenge in the fields of AGI and robotics. To advance research in this domain, complex
open-world testing environments such as Virtual Community [63] and SimWorld [55] have been
developed. These platforms facilitate the evaluation of intelligent behaviors of embodied agents
within complex social scenarios, ranging from autonomously navigating intersections characterized
by mixed pedestrian-vehicle traffic to assisting human agents in task execution. However, Virtual
Community is limited to supporting a maximum concurrency of 15-25 human agents and robots
within a single scene. Conversely, while SimWorld accommodates a larger population, its navigation
relies on predefined discrete waypoints, thereby failing to simulate the continuous crowd dynamics
required for rigorously evaluating the performance of realistic autonomous robots.
Leveraging TongSIM’s comprehensive asset library and robust control API, we employ the social
force model (SFM) to simulate high-fidelity, dynamic crowd behaviors. The system ensures stability
for simulations involving over 100 concurrent pedestrians. Virtual robots feature standard ROS2
14

Figure 12: Overview of the robot social navigation task in dynamic social scenarios.
integration, allowing for seamless interoperability with the broader robotic ecosystem. Furthermore,
the system supports human teleoperation of virtual avatars via VR, enabling subjective experience
analysis and interaction evaluation.
Within an urban street-level environment, we have designed a fundamental social navigation bench-
marking task. This task requires a robot to navigate to a designated target location inside a highly
dynamic crowd, characterized by randomly generated agents exhibiting diverse motion primitives.
This benchmark aims to evaluate the robot’s perception, planning, and social cognitive capabilities
within complex social settings, thereby providing a reproducible platform for research in human-
robot interaction (HRI). Figure 12 shows an overview of this benchmark.
The robot is tasked with navigating to a designated target location within a specified time limit while
traversing a complex environment. The core objective is to generate collision-free trajectories that
strictly adhere to proxemic constraints (i.e., maintaining appropriate social distances from pedes-
trians). This task serves as a benchmark to rigorously evaluate the autonomous agent’s perceptual
robustness, motion planning efficiency, and social compliance (cognitive understanding of social
norms) in dynamic, populated settings.
The robot perceives the environment through a multi-modal sensor suite, including: 1) RGB-D cam-
era, 2) 3D LiDAR, and 3) GPS module. The decision module outputs continuous control commands
via the standard ROS interface.
4.3.2 BASELINE ANDMETRICS
Baseline.To evaluate performance, we compare the following decision-making approaches. (1)
Human Teleoperation: Expert baseline via manual keyboard control. (2) Hierarchical planner
(DW A)[19]: A* global planner [20] + Dynamic Window Approach (DW A) local reactive controller.
(3) Hierarchical planner (MPPI)[51]: A* global planner + Model Predictive Path Integral (MPPI)
sampling-based local optimizer.
Evaluation Metrics.We employ a comprehensive set of metrics to quantitatively evaluate perfor-
mance. The evaluation module operates as a background process with a sampling frequency of 2
Hz.
•Efficiency (EFF):Measures the time efficiency of the navigation task based on theactual
completion time (T actual), normalized by the theoretical minimum time (T min) and the
maximum allotted time (Tmax). It is calculated as:
EFF= 1− Tactual −T min
Tmax −T min
(4)
•Success Rate (SRT):The ratio of successfully completed episodes to the total number of
experimental trials.
15

•Safety (SAF):A discrete scoring metric reflecting collision frequency. We assign a score
of 1.0 for zero collisions, 0.5 for 1–3 collisions, and 0.0 for more than 3 collisions.
•Social Norm Compliance (SNC):quantifies the percentage of task time during which the
robot intrudes into a human’s personal space, distinguishing Type-1 intrusions (distance
d <0.45m) and Type-2 intrusions (distance0.45m≤d≤1.2m).
•Total Score:A weighted aggregate score quantifying overall performance:
Total= 100×(0.2·EFF+ 0.2·SRT+ 0.3·SAF+ 0.3·SNC)(5)
4.3.3 EXPERIMENTS ANDRESULTS
Table 5: Performance comparison of baseline methods in the crowded intersection crossing task.
The test environment consists of a circular area (r= 20m) populated with 30 randomly moving
pedestrians, with a minimum start-to-goal distance of 40 m.
Baseline Robot EFF SRT SAF SNC Total
Human Teleoperation Unitree Go20.89 1.0 0.95 0.88 92.7
A∗ + DW A Unitree Go2 0.42 0.1 0 0 10.4
A∗ + MPPI Unitree Go2 0.73 0.6 0.25 0.31 43.1
As presented in Table 5, there is a marked disparity in performance across the evaluated decision-
making baselines within the fundamental social navigation task. Human Teleoperation achieved
superior performance across all four metrics (Total Score = 92.7), underscoring the human capacity
to leverage contextual reasoning and social cognition for high-quality navigation amidst complex
crowd dynamics. In stark contrast, globalA ∗ with local DW A planner exhibited instability in highly
dynamic scenarios, recording an exceptionally low success rate (SRT = 0.1). The method suffered
from frequent collisions and severe spatial intrusions, resulting in zero scores for both safety (SAF)
and social norm compliance (SNC), yielding a total score of only 10.4. This highlights the inad-
equacy of local planners relying solely on geometric constraints when confronting the stochastic
nature of multi-agent behaviors. While globalA ∗ with local MPPI planner demonstrated improve-
ments in efficiency and success rates through sampling-based optimization (achieving moderate per-
formance in safety and social compliance, and total score = 43.1) it still falls significantly short of
human benchmarks. This performance gap indicates that traditional planning frameworks, lacking
social behavioral understanding, struggle to adapt to dense crowd interactions.
The quantitative experimental results validate a core conclusion: in complex, dynamic social en-
vironments, the absence of social contextual reasoning and normative cognition causes traditional
autonomous planning methods to systematically lag behind human performance in terms of safety,
success rate, and social compliance. Embodied agents relying exclusively on geometric obstacle
avoidance or local optimization cannot achieve reliable and socially normative interactive behav-
iors. This critical limitation emphasizes the necessity of integrating models endowed with social
cognitive capabilities.
4.4 PRIMARYCOMPOSITETASKS: HOUSEHOLDBENCHMARKINGTEST
4.4.1 BENCHMARKOVERVIEW
Recent advancements in multimodal large language models (MLLMs) have significantly enhanced
AI capabilities in perception and linguistic comprehension. However, existing benchmarks (e.g., Im-
ageNet [16], COCO [26], VQA [3]) predominantly focus on isolated, domain-specific tasks. These
benchmarks suffer from limitations regarding hyperspecialization and susceptibility to overfitting,
making them insufficient for comprehensively gauging a model’s capabilities in open-ended, dy-
namic real-world environments—competencies essential for the progression towards AGI. Although
multi-task platforms like MMBench [27] offer multidimensional testing, they generally lack embod-
ied interaction capabilities, failing to evaluate model reasoning and action execution within physical
and social contexts.
To address this critical limitation, we propose a novel evaluation paradigm: an embodied composite
task benchmark situated in everyday household environments and drawing inspiration from early
16

Figure 13: Overview of the primary family composite tasks benchmark.
childhood developmental psychology, as shown in Figure 13. The core objective of this benchmark
is to evaluate how MLLM agents integrate perception, reasoning, and action to accomplish com-
posite tasks requiring synergistic capabilities, thereby providing a more realistic assessment of their
general intelligence.
4.4.2 TESTPROCEDURE
Focusing on composite task scenarios frequent in household settings, we designed an evaluation set
comprising eight task types, categorized into three core domains:
•Object Understanding:Including object counting and gift selection.
•Spatial Intelligence:Including block construction, puzzle solving, and understanding but-
ton functionality.
•Social Activity:Including table setting, room organization, and luggage preparation.
We construct high-fidelity 3D virtual home environments within the TongSIM simulation platform to
serve as a testbed for model evaluation. Leveraging prompt engineering, we encapsulate the target
models into agents capable of executing tasks within these embodied interactive settings. Conse-
quently, we establish a standardized perception-reasoning-action loop framework for the MLLMs
under assessment:
•Perception:At each time step, the agent receives observational data from the environ-
ment, comprising multi-view RGB images and JSON scene descriptions containing object
attributes (e.g., name, color, position).
•Reasoning and Decision-Making:Based on observational data and natural language task
goals, the MLLM employs a ReAct-style reasoning process to output a natural language
reasoning trace and an executable sequence of API calls.
•Action:The system executes the API call sequence (e.g., MoveToObject, PickUp), which
encompasses both atomic and high-level actions, thereby driving the virtual character to
interact with the environment.
•Loop:This process iterates until the task is completed or a timeout occurs.
To directly assess the intrinsic capabilities of the models, we did not perform retraining or introduce
external augmentation modules; instead, we encapsulated the MLLMs as embodied agents solely
through carefully designed prompts.
17

4.4.3 EXPERIMENTS ANDRESULTS
We conducted a systematic evaluation of 17 proprietary and open-source MLLMs (including the
GPT, Gemini, Claude, and Llama series). The primary results are as follows:
•Overall Suboptimal Performance:Average scores across all models on composite tasks
were universally low. The top-performing model, Gemini-2.5-Pro, achieved an aver-
age score of merely 24.53/100. This indicates a substantial gap between state-of-the-art
MLLMs and the requirements for handling real-world embodied tasks.
•Proprietary vs. Open-Source Models:While proprietary models generally outperformed
open-source counterparts, the margin was not overwhelming. The best-performing open-
source model was Llama-4-Maverick, with a score of 14.48.
•Domain-Specific Analysis:(1) Object Understanding proved to be the relative strength of
the models; for instance, GPT-5 achieved a score of 69.06 in the “Gift Selection” task. This
suggests that current models possess certain advantages in perception and basic classifica-
tion tasks. (2) Spatial Intelligence emerged as the most challenging domain, with models
scoring extremely low on tasks such as block construction and puzzle solving. This iden-
tifies spatial reasoning, physical understanding, and manipulation planning as the weakest
links in current MLLMs. (3) Social Activity performance was inconsistent, with different
models leading in different tasks; however, even the highest scores hovered in the 20-30
range. This reflects difficulties in comprehending complex social contexts and executing
goal-oriented actions.
Experimental results, shown in Table 6, demonstrate that while current MLLMs have made signif-
icant strides in perception and language tasks, their architectures, training mechanisms, and mul-
timodal fusion strategies remain insufficient to support the composite capabilities required for em-
bodied tasks. Future research must prioritize the in-depth development of embodied reasoning, spa-
tial intelligence, and social understanding. The benchmark proposed in this work serves as a vital
evaluation tool and provides directional guidance for advancing MLLMs toward general embodied
intelligence.
4.5 ADVANCEDCOMPOSITETASKS: SPATIALLYSITUATEDSOCIALINTELLIGENCETEST
4.5.1 BENCHMARKOVERVIEW
The integration of embodied agents into human environments demands embodied social intelli-
gence: reasoning over both social norms and physical constraints. However, existing evaluations
fail to address this integration, as they are limited to either disembodied social reasoning (e.g., in
text) or socially-agnostic physical tasks. Both approaches fail to assess an agent’s ability to integrate
and trade off both physical and social constraints within a realistic, embodied context.
Table 6: Model performance comparison on the primary family composite tasks benchmark.
Model Object Understanding Spatial Intelligence Social Activity MeanCounting
Objects
Selecting
Gifts
Building
Blocks
Jigsaw
Puzzle
Understanding
Buttons
Setting
Tables
Tidying Up
Rooms
Preparing
Baggage
Gemini-2.5-Pro 48.00 68.06 10.00 5.05 3.33 26.68 22.7712.38 24.53Gemini-2.5-Flash 42.00 68.20 5.50 5.30 3.33 25.8323.2211.05 23.05o354.0065.92 10.00 6.40 3.33 14.31 18.77 10.30 22.88GPT-5 36.0069.063.75 6.03 3.3328.6816.00 9.50 21.54Claude-3.7-Sonnet 46.00 59.74 8.88 6.28 0.00 23.76 16.12 3.40 20.52Claude-4-Sonnet 44.00 65.44 8.75 6.03 0.00 19.81 14.85 5.18 20.51Doubao-1.5-vision-pro 36.00 56.7012.506.885.0024.17 4.22 7.75 19.15Claude-3.5-Sonnet 42.00 64.24 8.00 4.50 0.00 12.33 13.47 6.00 18.82Grok 3 52.00 50.24 9.888.000.00 8.37 17.20 3.35 18.63o4-mini 38.00 66.40 0.00 6.62 3.33 13.67 1.52 4.23 16.72GPT-4o 32.00 46.30 10.00 7.08 3.33 18.42 6.30 8.18 16.45GPT-4o-mini 34.00 54.96 5.75 7.05 1.67 19.07 1.50 3.75 15.97Qwen-VL-max 44.00 48.14 0.00 7.55 0.00 15.96 1.25 0.00 14.61Llama-4-Maverick 36.00 50.30 3.75 6.58 0.00 15.75 0.42 3.00 14.48Llama-4-Scout 28.00 42.56 6.25 5.72 0.00 8.94 1.38 2.00 11.86Qwen-VL-plus 6.00 34.16 0.00 7.65 0.00 16.67 1.82 0.38 8.33Llama-3.2 6.00 6.80 0.00 4.60 0.00 4.67 0.42 0.00 2.81
18

Figure 14: A typical seat arrangement task involves a given room layout and several NPCs. The
agent under test (T-Agent) needs to interact with the NPCs and explore the room to devise a seating
arrangement that satisfies everyone.
To address this challenge, we introduce spatially situated social intelligence test (S 3IT), a bench-
mark specifically designed to evaluate embodied social intelligence. As shown in Figure 14, it is
centered on a novel and challenging seat-ordering task, requiring an agent to arrange seating in a
3D environment for a group of LLM-driven NPCs with diverse identities, preferences, and intricate
interpersonal relationships. Our procedurally extensible framework generates a vast and diverse
scenario space with controllable difficulty, compelling the agent to acquire preferences through ac-
tive dialogue, perceive the environment via autonomous exploration, and perform multi-objective
optimization within a complex constraint network.
In this benchmark, we constructed 5 scene environments with dynamic layout characteristics , where
key facilities (e.g., chairs, furniture layouts) support parametric configuration. Simultaneously, we
established a virtual community comprising 59 NPCs with independent background settings, and de-
fined their internal complex family and social relationship networks. Based on this, we constructed
7,000 problems. Each problem includes one room and several NPCs; while basic information re-
mains invariant, we additionally configured specific hobbies, seating preferences, and conflicts with
others for each NPC in every problem. Furthermore, we assigned 3-Likert point intensities (weights)
to these preferences and conflicts to enrich the problems.
4.5.2 BASELINES ANDTESTPROCEDURE
Within this benchmark, we propose a testing framework designed to integrate LLMs. To enable
the agents under test to effectively comprehend and execute the seating arrangement tasks, we have
systematically designed and standardized the inputs, outputs, and prompt structures. The pipeline
comprises three phases for testing the agent that is named as “T-Agent”. In Phase I (NPC Prefer-
ence Extraction and Summarization), the T-Agent constructs detailed preference profiles for each
NPC. Then, in Phase II (Environmental Cognition ), the T-Agent needs to construct a structured
representation of the 3D environment through comprehensive exploration. Finally, in Phase III
(Multi-Constraint Decision-Making), the T-Agent integrates information from the preceding phases
to generate, reflect, and iteratively refine seating solutions. To enable scalable evaluation, we in-
troduce an automated scoring framework. This framework evaluates the preference satisfaction of
agent-generated seating plans, thereby providing an objective, quantitative metric for each solution.
Furthermore, to analyze the T-Agent’s capability in prioritizing based on weights, we statistically
tracked its preference satisfaction based on their strengths. We define the prioritization gap (PG) as:
PG=S high −S low (6)
whereS high denotes the satisfying rate of high-weighted preferences, andSlow denotes the satisfying
rate of low-weighted preferences.
4.5.3 EXPERIMENTS ANDRESULTS
As shown in Table 7, Gemini-2.5-pro emerged as the SOTA model (47.8) and was uniquely capable
of exceeding 40 on the “Embodied Preference” dimension. These models exhibit a consistent trend
that scores are lowest in the embodied dimension, followed by the social dimension. In contrast,
19

Table 7: Model performances on the S 3IT benchmark’s test set. Best results are in bold. PG stands
for the prioritization gap.
Model Embodied Social Conflict PG Average
Gemini-2.5-pro40.656.2 85.7 8.847.8
o3 32.9 53.8 89.0 12.7 43.1
GPT-5 29.056.986.115.442.7
o4-mini 29.0 54.589.56.8 41.4
GPT-4.1 23.3 43.2 55.4 3.8 29.3
Doubao-1.5 24.6 43.0 62.5 3.8 28.3
GPT-4o 24.6 43.0 51.7 3.3 28.2
GPT-4.1-mini 22.8 39.3 42.5 3.7 26.8
Claude-4.5 19.1 37.6 46.0 4.8 23.1
GPT-4o-mini 16.7 34.7 45.8 1.6 19.3
performance in the conflict dimension is generally strong across the board, with some models even
demonstrating a good capacity for conflict resolution. These findings validate the hypothesis that
spatial intelligence is the cornerstone of effective embodied social reasoning. All models demon-
strated positive PG scores, indicating that they have a fundamental ability to distinguish preference
strengths. Higher-priority preferences are fulfilled with greater precedence. Among the evaluated
models, GPT-5, with an updated adaptive reasoning architecture, excels at considering preferences
of varying intensities.
5 DISCUSSION
5.1 VARIOUS BENCHMARKS
TongSIM is established not merely as a simulation platform, but as a holistic proving ground
aimed at catalyzing agent evolution. Underpinned by a versatile suite of benchmarks, our multi-
dimensional architectural philosophy enables a full-spectrum diagnosis and validation of agent pro-
ficiency.
First, a distinguishing feature of our platform is the hierarchical evaluation of agent capabilities. Our
benchmarks span a comprehensive spectrum, ranging from low-level perception and locomotion to
high-level complex tasks and social intelligence. At the foundational level, we assess atomic single-
agent capabilities, including locomotion, steering, and basic visual perception, which are incorpo-
rated into all our proposed benchmarks. Building upon this, single-agent tasks involve higher-level
assessments such as object attribute recognition, spatial memory construction, and semantic naviga-
tion. For instance, requiring an agent to explore an unknown room to locate a “paper ball” tests its
semantic understanding of the environment. At the highest level, the platform emphasizes sociality
and collaborative intelligence. This encompasses high-dimensional challenges ranging from multi-
agent collaboration (e.g., the MACS task) to complex scenarios (e.g., navigation in dense crowds
and execution of complex household tasks). These benchmarks aim to advance the development of
agents towards AGI equipped with social attributes.
Second, high-fidelity simulation scenarios are pivotal to bridging the Sim-to-Real gap. In con-
trast to traditional grid worlds or symbolic, low-fidelity environments, all tasks within our plat-
form are situated in photorealistic environments constructed upon advanced physics engines and
ray-tracing technologies. TongSIM scenarios encompass complex illumination variations, specular
reflections, shadow occlusions, and rich textural details, thereby compelling the agents’ visual sys-
tems to demonstrate robustness against real-world sensory noise. Furthermore, TongSIM features
rich physical simulation capabilities, enabling the modeling of rigid body dynamics, fluid interac-
tions, and deformable object deformations (e.g., cloth and liquids). Under such constraints, the
planning capabilities of agents can be evaluated within scenarios that closely approximate reality.
For instance, when grasping a cup filled with water, the agent must account for shifts in the center
of gravity and friction. This training regime ensures that model parameters, upon transfer to phys-
ical robotic hardware, can directly adapt to real-world physical constraints, significantly mitigating
20

the costs associated with fine-tuning. Although this paper does not go into detail about this fea-
ture, the experimental development work has been basically completed, which will be introduced in
subsequent work.
We prioritize agent generalizability and are dedicated to the pursuit of AGI; accordingly, TongSIM is
engineered to support massive, large-scale tasks to facilitate this objective. To prevent agents from
overfitting to specific spatial configurations, the platform is designed to enable large-scale scene
generation. Leveraging procedural generation, we can synthesize thousands of indoor environments
featuring diverse layouts and stylistic variations. This diversity ensures that agents acquire gener-
alized interaction logic (e.g., understanding the affordance that a door requires pushing or pulling)
rather than relying on the rote memorization of map coordinates. An extensive suite of additional
benchmarks will be progressively released to the research community.
5.2 POTENTIALAPPLICATIONS
In light of our ultimate objective to achieve AGI, the inception and architectural design of this
platform are intrinsically aligned with this vision. Rather than merely supplying datasets, we provide
a holistic ecosystem designed to incubate high-level intelligence.
TongSIM offers users an exceptional degree of freedom and extensibility, thereby broadening its
multidisciplinary application horizons:
•Planning in Symbolic Space:Researchers can leverage high-level APIs to focus on task
decomposition, causal reasoning, and the application of knowledge graphs, without being
encumbered by low-level control dynamics.
•End-to-End Embodied Control:Researchers in reinforcement learning and imitation
learning can utilize the comprehensive interfaces and rich environmental data (e.g., RGB-D
images, semantic object labels) to train end-to-end neural networks.
•Verification of Hybrid Architectures:The platform facilitates the validation of “LLM-
Brain + Controller-Cerebellum” hybrid architectures. For instance, users can employ LLMs
for high-level strategic planning while invoking low-level motion primitives to execute spe-
cific operations.
To transcend the limitations of traditional platforms restricted to fixed tasks, we provide standardized
Python/C++ APIs, diverse virtual avatars, and extensive functional capabilities. These tools enable
users to rapidly construct custom tasks:
•Domestic Service Scenarios:Users can define a “room tidying” task, requiring the agent
to identify debris on the floor, classify items, and place them into storage containers.
•Operations in Extreme Environments:Simulating post-fire ruin scenarios to train agents
in Search and Rescue and hazardous material removal, testing their robustness within
chaotic environments.
•Human-Robot Interaction:Configuring NPCs with social attributes to train agents in
comprehending human gestures and gaze intent, as well as engaging in natural language
dialogue.
These tasks are not confined to the platform’s preset benchmarks; researchers can rapidly construct
experimental environments tailored to their specific scientific hypotheses, thereby significantly en-
hancing iteration efficiency.
5.3 FUTUREWORKS
Currently, the platform is undergoing iterative development. We are committed to progressively re-
fining both indoor and outdoor environments, expanding the benchmark suite, and releasing these
contributions to the open-source community. Regarding environmental expansion, while our current
focus lies within complex indoor domestic environments, we are actively constructing an expansive
world model. Future iterations will extend into outdoor scenarios, enriching supported interac-
tions and semantic annotations. This includes the simulation of urban street interactions, crowd and
traffic network dynamics, unstructured natural terrains (e.g., forests, mountains), and specialized
21

outdoor zones (e.g., industrial complexes). These developments are poised to support research in
autonomous driving, logistics distribution, and field exploration robotics. Furthermore, we plan to
enhance the temporal and environmental dynamics of the simulator. Future scenes will transcend
static snapshots by incorporating diurnal cycles, meteorological variations (e.g., rain, fog, snow),
and dynamic obstacles (e.g., pedestrians, vehicles), thereby approximating the stochasticity and
complexity of the real world.
The future of embodied AI is inextricably linked to human cognitive guidance and cross-reality
interaction. The emerging paradigm of symmetrical reality [60, 58], utilizing human-in-the-loop
methodologies across physical and virtual worlds, grants agents direct exposure to data distributions
of hybrid environments, fostering robust training for extensible tasks.
Through these endeavors, we envision this platform not merely as a testing tool, but as a stepping
stone toward a future of human-machine symbiosis, contributing substantive momentum to the real-
ization of AGI endowed with comprehensive perception, reasoning, and actuation capabilities.
6 CONCLUSIONS
This paper formally introduces TongSIM, a universal training and evaluation platform for embod-
ied AI designed to bridge the simulation-to-reality gap through high-fidelity simulation technolo-
gies. TongSIM establishes an expansive world featuring 115 meticulously crafted interactive indoor
scenes and large-scale continuous urban environments, and provides highly challenging multimodal
sensory inputs to agents. Leveraging high-fidelity physics simulation, native parallel training sup-
port, and diverse agent driving modalities, TongSIM establishes a task spectrum that surpasses ex-
isting platforms.
We design and implement five benchmark categories within the 3D interactive environments, cover-
ing single-agent autonomous navigation, multi-agent cooperation, social navigation in human-robot
hybrid environments, and both basic and advanced household service tasks. Extensive empirical
evaluations reveal that while agents driven by reinforcement learning and MLLMs excel in specific
tasks, they exhibit significant deficiencies in long-horizon planning, complex spatial reasoning, and
adherence to social norms.
To foster community development, we release TongSIM as an open-source platform. We envision
this infrastructure serving as a catalyst for general embodied intelligence research, empowering
both academia and industry to cultivate next-generation agents capable of robust perception, deep
reasoning, and efficient cooperation within open and dynamic environments.
REFERENCES
[1] M. Ahn, A. Brohan, N. Brown, Y . Chebotar, O. Cortes, B. David, C. Finn, C. Fu, K. Gopalakr-
ishnan, K. Hausman, et al. Do as i can, not as i say: Grounding language in robotic affordances.
arXiv preprint arXiv:2204.01691, 2022.
[2] P. Anderson, Q. Wu, D. Teney, J. Bruce, M. Johnson, N. S ¨underhauf, I. Reid, S. Gould, and
A. Van Den Hengel. Vision-and-language navigation: Interpreting visually-grounded naviga-
tion instructions in real environments. InProceedings of the IEEE conference on computer
vision and pattern recognition, pages 3674–3683, 2018.
[3] S. Antol, A. Agrawal, J. Lu, M. Mitchell, D. Batra, C. L. Zitnick, and D. Parikh. Vqa: Visual
question answering. InProceedings of the IEEE International Conference on Computer Vision,
pages 2425–2433, 2015.
[4] G. Authors. Genesis: A generative and universal physics engine for robotics and beyond,
December 2024.
[5] S. Bailis, J. Friedhoff, and F. Chen. Werewolf arena: A case study in llm evaluation via social
deduction.arXiv preprint arXiv:2407.13943, 2024.
[6] A. Bhattacharjee, Y . Zeng, S. Y . Xu, D. Kulzhabayeva, M. Ma, R. Kornfield, S. I. Ahmed,
A. Mariakakis, M. P. Czerwinski, A. Kuzminykh, et al. Understanding the role of large lan-
guage models in personalizing and scaffolding strategies to combat academic procrastination.
22

InProceedings of the 2024 CHI Conference on Human Factors in Computing Systems, pages
1–18, 2024.
[7] W. Bu, Y . Wu, Q. Yu, M. Gao, B. Miao, Z. Zhang, K. Pan, Y . Li, M. Li, W. Ji, et al. What limits
virtual agent application? omnibench: A scalable multi-dimensional benchmark for essential
virtual agent capabilities.arXiv preprint arXiv:2506.08933, 2025.
[8] M. Cai, X. Chen, Y . An, J. Zhang, X. Wang, W. Xu, W. Zhang, and T. Liu. Cookbench: A
long-horizon embodied planning benchmark for complex cooking scenarios.arXiv preprint
arXiv:2508.03232, 2025.
[9] A. Chang, A. Dai, T. Funkhouser, M. Halber, M. Niessner, M. Savva, S. Song, A. Zeng, and
Y . Zhang. Matterport3d: Learning from rgb-d data in indoor environments.arXiv preprint
arXiv:1709.06158, 2017.
[10] Z. Chu, S. Wang, J. Xie, T. Zhu, Y . Yan, J. Ye, A. Zhong, X. Hu, J. Liang, P. S. Yu, et al. Llm
agents for education: Advances and applications.arXiv preprint arXiv:2503.11733, 2025.
[11] D.-M. C ´ordova-Esparza. Ai-powered educational agents: Opportunities, innovations, and eth-
ical challenges.Information, 16(6):469, 2025.
[12] M. Cordts, M. Omran, S. Ramos, T. Rehfeld, M. Enzweiler, R. Benenson, U. Franke, S. Roth,
and B. Schiele. The cityscapes dataset for semantic urban scene understanding. InProceedings
of the IEEE Conference on Computer Vision and Pattern Recognition (CVPR), June 2016.
[13] S. Cui, X. He, J. Han, Z. Zhang, and Y . Peng. Ability decomposition and difficulty quantifica-
tion of visual tasks: Towards systematic evaluations of artificial general intelligence.Science
China Technological Sciences, 68, 2025.
[14] C. S. De Witt, T. Gupta, D. Makoviichuk, V . Makoviychuk, P. H. Torr, M. Sun, and S. White-
son. Is independent learning all you need in the starcraft multi-agent challenge?arXiv preprint
arXiv:2011.09533, 2020.
[15] M. Deitke, E. VanderBilt, A. Herrasti, L. Weihs, K. Ehsani, J. Salvador, W. Han, E. Kolve,
A. Kembhavi, and R. Mottaghi. Procthor: Large-scale embodied ai using procedural genera-
tion.Advances in Neural Information Processing Systems, 35:5982–5994, 2022.
[16] J. Deng, W. Dong, R. Socher, L.-J. Li, K. Li, and L. Fei-Fei. Imagenet: A large-scale hierar-
chical image database. InProceedings of the IEEE conference on computer vision and pattern
recognition, pages 248–255. Ieee, 2009.
[17] G. Dulac-Arnold, N. Levine, D. J. Mankowitz, J. Li, C. Paduraru, S. Gowal, and T. Hester.
Challenges of real-world reinforcement learning: definitions, benchmarks and analysis.Ma-
chine Learning, 110(9):2419–2468, 2021.
[18] K. Fang, P. Yin, A. Nair, H. R. Walke, G. Yan, and S. Levine. Generalization with lossy
affordances: Leveraging broad offline data for learning visuomotor tasks. InConference on
Robot Learning, pages 106–117. PMLR, 2023.
[19] D. Fox, W. Burgard, and S. Thrun. The dynamic window approach to collision avoidance.
IEEE Robotics & Automation Magazine, 4(1):23–33, 1997.
[20] P. E. Hart, N. J. Nilsson, and B. Raphael. A formal basis for the heuristic determination of
minimum cost paths.IEEE Transactions on Systems Science and Cybernetics, 4(2):100–107,
1968.
[21] Y . Hong, Z. Zheng, P. Chen, Y . Wang, J. Li, and C. Gan. Multiply: A multisensory object-
centric embodied large language model in 3d world. InProceedings of the IEEE/CVF Confer-
ence on Computer Vision and Pattern Recognition, pages 26406–26416, 2024.
[22] E. Kolve, R. Mottaghi, W. Han, E. VanderBilt, L. Weihs, A. Herrasti, M. Deitke, K. Ehsani,
D. Gordon, Y . Zhu, et al. Ai2-thor: An interactive 3d environment for visual ai.arXiv preprint
arXiv:1712.05474, 2017.
23

[23] C. Li, F. Xia, R. Mart´ın-Mart´ın, M. Lingelbach, S. Srivastava, B. Shen, K. Vainio, C. Gokmen,
G. Dharan, T. Jain, et al. igibson 2.0: Object-centric simulation for robot learning of everyday
household tasks.arXiv preprint arXiv:2108.03272, 2021.
[24] C. Li, R. Zhang, J. Wong, C. Gokmen, S. Srivastava, R. Mart ´ın-Mart´ın, C. Wang, G. Levine,
M. Lingelbach, J. Sun, M. Anvari, M. Hwang, M. Sharma, A. Aydin, D. Bansal, S. Hunter,
K.-Y . Kim, A. Lou, C. R. Matthews, I. Villa-Renteria, J. H. Tang, C. Tang, F. Xia, S. Savarese,
H. Gweon, K. Liu, J. Wu, and L. Fei-Fei. BEHA VIOR-1k: A benchmark for embodied AI with
1,000 everyday activities and realistic simulation. InProceedings of the 6th Annual Conference
on Robot Learning, 2022.
[25] H. Li, Y . Wang, and H. Qu. Where are we so far? understanding data storytelling tools from the
perspective of human-ai collaboration. InProceedings of the 2024 CHI Conference on Human
Factors in Computing Systems, pages 1–19, 2024.
[26] T.-Y . Lin, M. Maire, S. Belongie, J. Hays, P. Perona, D. Ramanan, P. Doll´ar, and C. L. Zitnick.
Microsoft coco: Common objects in context. InEuropean Conference on Computer Vision,
pages 740–755. Springer, 2014.
[27] Y . Liu, H. Duan, Y . Zhang, B. Li, S. Zhang, W. Zhao, Y . Yuan, J. Wang, C. He, Z. Liu, et al.
Mmbench: Is your multi-modal model an all-around player? InEuropean Conference on
Computer Vision, pages 216–233. Springer, 2024.
[28] V . Makoviychuk, L. Wawrzyniak, Y . Guo, M. Lu, K. Storey, M. Macklin, D. Hoeller, N. Rudin,
A. Allshire, A. Handa, et al. Isaac gym: High performance gpu-based physics simulation for
robot learning.arXiv preprint arXiv:2108.10470, 2021.
[29] L. Meincke and C. Terwiesch. Reimagining customer service journeys with llms: A framework
for chatbot design and workflow integration. 2025.
[30] J. S. Park, J. O’Brien, C. J. Cai, M. R. Morris, P. Liang, and M. S. Bernstein. Generative agents:
Interactive simulacra of human behavior. InProceedings of the 36th annual acm symposium
on user interface software and technology, pages 1–22, 2023.
[31] Y . Peng, J. Han, Z. Zhang, L. Fan, T. Liu, S. Qi, X. Feng, Y . Ma, Y . Wang, and S.-C. Zhu. The
tong test: Evaluating artificial general intelligence through dynamic embodied physical and
social interactions.Engineering, 34:12–22, 2024.
[32] X. Puig, K. Ra, M. Boben, J. Li, T. Wang, S. Fidler, and A. Torralba. Virtualhome: Simulating
household activities via programs. InProceedings of the IEEE conference on computer vision
and pattern recognition, pages 8494–8502, 2018.
[33] X. Puig, T. Shu, S. Li, Z. Wang, Y .-H. Liao, J. B. Tenenbaum, S. Fidler, and A. Torralba.
Watch-and-help: A challenge for social perception and human-ai collaboration.arXiv preprint
arXiv:2010.09890, 2020.
[34] X. Puig, E. Undersander, A. Szot, M. D. Cote, T.-Y . Yang, R. Partsey, R. Desai, A. W. Clegg,
M. Hlavac, S. Y . Min, et al. Habitat 3.0: A co-habitat for humans, avatars and robots.arXiv
preprint arXiv:2310.13724, 2023.
[35] S. Rao, W. Xu, M. Xu, J. Leandro, K. Lobb, G. DesGarennes, C. Brockett, and B. Dolan. Col-
laborative quest completion with llm-driven non-player characters in minecraft.arXiv preprint
arXiv:2407.03460, 2024.
[36] N. Roy, I. Posner, T. Barfoot, P. Beaudoin, Y . Bengio, J. Bohg, O. Brock, I. Depatie, D. Fox,
D. Koditschek, et al. From machine learning to robotics: Challenges and opportunities for
embodied intelligence.arXiv preprint arXiv:2110.15245, 2021.
[37] M. Savva, A. X. Chang, A. Dosovitskiy, T. Funkhouser, and V . Koltun. Minos: Multimodal
indoor simulator for navigation in complex environments.arXiv preprint arXiv:1712.03931,
2017.
24

[38] M. Savva, A. Kadian, O. Maksymets, Y . Zhao, E. Wijmans, B. Jain, J. Straub, J. Liu, V . Koltun,
J. Malik, et al. Habitat: A platform for embodied ai research. InProceedings of the IEEE/CVF
international conference on computer vision, pages 9339–9347, 2019.
[39] J. Schulman, F. Wolski, P. Dhariwal, A. Radford, and O. Klimov. Proximal policy optimization
algorithms.arXiv preprint arXiv:1707.06347, 2017.
[40] Y . Seo, D. Hafner, H. Liu, F. Liu, S. James, K. Lee, and P. Abbeel. Masked world models for
visual control. InConference on Robot Learning, pages 1332–1344. PMLR, 2023.
[41] H. Shakeri, C. Neustaedter, and S. DiPaola. Saga: Collaborative storytelling with gpt-3. In
Companion Publication of the 2021 Conference on Computer Supported Cooperative Work
and Social Computing, pages 163–166, 2021.
[42] J. Shi, J. Li, Q. Ma, Z. Yang, H. Ma, and L. Li. Chops: Chat with customer profile systems for
customer service with llms.arXiv preprint arXiv:2404.01343, 2024.
[43] M. Shridhar, J. Thomason, D. Gordon, Y . Bisk, W. Han, R. Mottaghi, L. Zettlemoyer, and
D. Fox. Alfred: A benchmark for interpreting grounded instructions for everyday tasks. In
Proceedings of the IEEE/CVF conference on computer vision and pattern recognition, pages
10740–10749, 2020.
[44] M. Shridhar, X. Yuan, M.-A. Cˆot´e, Y . Bisk, A. Trischler, and M. Hausknecht. Alfworld: Align-
ing text and embodied environments for interactive learning.arXiv preprint arXiv:2010.03768,
2020.
[45] S. Sinha and Y . M. Lee. Challenges with developing and deploying ai models and applications
in industrial systems.Discover Artificial Intelligence, 4(1):55, 2024.
[46] A. Szot, A. Clegg, E. Undersander, E. Wijmans, Y . Zhao, J. Turner, N. Maestre, M. Mukadam,
D. S. Chaplot, O. Maksymets, et al. Habitat 2.0: Training home assistants to rearrange their
habitat.Advances in neural information processing systems, 34:251–266, 2021.
[47] X. Tang, J. Li, Y . Liang, S.-c. Zhu, M. Zhang, and Z. Zheng. Mars: Situated inductive rea-
soning in an open-world environment.Advances in Neural Information Processing Systems,
37:17830–17869, 2024.
[48] E. Todorov, T. Erez, and Y . Tassa. Mujoco: A physics engine for model-based control. In
Proceedings of the IEEE/RSJ International Conference on Intelligent Robots and Systems,
pages 5026–5033. IEEE, 2012.
[49] H. Wang, J. Chen, W. Huang, Q. Ben, T. Wang, B. Mi, T. Huang, S. Zhao, Y . Chen, S. Yang,
et al. Grutopia: Dream general robots in a city at scale.arXiv preprint arXiv:2407.10943,
2024.
[50] Y . Wang, Z. Xian, F. Chen, T.-H. Wang, Y . Wang, K. Fragkiadaki, Z. Erickson, D. Held, and
C. Gan. Robogen: Towards unleashing infinite data for automated robot learning via generative
simulation.arXiv preprint arXiv:2311.01455, 2023.
[51] G. Williams, A. Aldrich, and E. Theodorou. Model predictive path integral control using
covariance variable importance sampling.arXiv preprint arXiv:1509.01149, 2015.
[52] F. Xia, W. B. Shen, C. Li, P. Kasimbeg, M. E. Tchapmi, A. Toshev, R. Mart ´ın-Mart´ın, and
S. Savarese. Interactive gibson benchmark: A benchmark for interactive navigation in cluttered
environments.IEEE Robotics and Automation Letters, 5(2):713–720, 2020.
[53] F. Xiang, Y . Qin, K. Mo, Y . Xia, H. Zhu, F. Liu, M. Liu, H. Jiang, Y . Yuan, H. Wang, et al.
Sapien: A simulated part-based interactive environment. InProceedings of the IEEE/CVF
conference on computer vision and pattern recognition, pages 11097–11107, 2020.
[54] X. Xie, H. Liu, Z. Zhang, Y . Qiu, F. Gao, S. Qi, Y . Zhu, and S.-C. Zhu. Vrgym: A virtual testbed
for physical and interactive ai. InProceedings of the ACM Turing Celebration Conference-
China, pages 1–6, 2019.
25

[55] X. Ye, J. Ren, Y . Zhuang, X. He, Y . Liang, Y . Yang, M. Dogra, X. Zhong, E. Liu, K. Benavente,
et al. Simworld: An open-ended simulator for agents in physical and social worlds. InPro-
ceedings of the Thirty-ninth Annual Conference on Neural Information Processing Systems.
[56] C. Yu, A. Velu, E. Vinitsky, J. Gao, Y . Wang, A. Bayen, and Y . Wu. The surprising effectiveness
of ppo in cooperative multi-agent games.Advances in Neural Information Processing Systems,
35:24611–24624, 2022.
[57] Z. Zhang, Y . Lan, Y . Chen, L. Wang, X. Wang, and H. Wang. Dvm: Towards controllable llm
agents in social deduction games. InProceedings of the IEEE International Conference on
Acoustics, Speech and Signal Processing (ICASSP), pages 1–5. IEEE, 2025.
[58] Z. Zhang, C. Wang, D. Weng, Y . Liu, and Y . Wang. Symmetrical reality: Toward a unified
framework for physical and virtual reality. InProceedings of the IEEE Conference on Virtual
Reality and 3D User Interfaces (VR), pages 1275–1276. IEEE, 2019.
[59] Z. Zhang, D. Weng, H. Jiang, Y . Liu, and Y . Wang. Inverse augmented reality: a virtual agent’s
perspective. InProceedings of the IEEE International Symposium on Mixed and Augmented
Reality Adjunct (ISMAR-Adjunct), pages 154–157. IEEE, 2018.
[60] Z. Zhang, Z. Zhang, Z. Jiao, Y . Su, H. Liu, W. Wang, and S.-C. Zhu. On the emergence
of symmetrical reality. InProceedings of the IEEE Conference Virtual Reality and 3D User
Interfaces (VR), pages 639–649. IEEE, 2024.
[61] A. Zhao, Y . Wu, Y . Yue, T. Wu, Q. Xu, M. Lin, S. Wang, Q. Wu, Z. Zheng, and G. Huang. Ab-
solute zero: Reinforced self-play reasoning with zero data.arXiv preprint arXiv:2505.03335,
2025.
[62] X. Zheng, H. Lin, K. He, Z. Wang, Q. FU, H. Fu, Z. Zheng, and Y . Liang. MCU: An evaluation
framework for open-ended game agents. InProceedings of the Forty-second International
Conference on Machine Learning, 2025.
[63] Q. Zhou, H. Zhang, X. Lin, Z. Zhang, Y . Chen, W. Liu, Z. Zhang, S. Chen, L. Fang, Q. Lyu,
et al. Virtual community: An open world for humans, robots, and society.arXiv preprint
arXiv:2508.14893, 2025.
26
