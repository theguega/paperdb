**Safety in Embodied AI: A Survey of Risks, Attacks, and Defenses** 





**Xiao Li**<sup>**1,***</sup> **, Xiang Zheng**<sup>**3,***</sup> **, Yifeng Gao**<sup>**1**</sup> **, Xinyu Xia**<sup>**4**</sup> **, Yixu Wang**<sup>**1**</sup> **, Xin Wang**<sup>**1**</sup> **, Ye Sun**<sup>**1**</sup> **, Yunhan Zhao**<sup>**1**</sup> **, Ming Wen**<sup>**1,2**</sup> **, Jiayu Li**<sup>**1**</sup> **, Zixing Chen**<sup>**1**</sup> **, Xun Gong**<sup>**4**</sup> **, Yi Liu**<sup>**3**</sup> **, Yige Li**<sup>**5**</sup> **, Yutao Wu**<sup>**6**</sup> **, Cong Wang**<sup>**3**</sup> **, Jun Sun**<sup>**5**</sup> **, Yixin Cao**<sup>**1,2**</sup> **, Zhineng Chen**<sup>**1**</sup> **, Jingjing Chen**<sup>**1**</sup> **, Tao Gui**<sup>**1,2**</sup> **, Qi Zhang**<sup>**1**</sup> **, Zuxuan Wu**<sup>**1,2**</sup> **, Xipeng Qiu**<sup>**1,2**</sup> **, Xuanjing Huang**<sup>**1**</sup> **, Tiehua Zhang**<sup>**7**</sup> **, Zhipeng Wei**<sup>**9**</sup> **, Kun Wang**<sup>**10**</sup> **, Xinfeng Li**<sup>**10**</sup> **, Hanxun Huang**<sup>**12**</sup> **, Sarah Erfani**<sup>**12**</sup> **, James Bailey**<sup>**12**</sup> **, Jianping Wang**<sup>**3**</sup> **, Chaowei Xiao**<sup>**13**</sup> **, Ran He**<sup>**11**</sup> **, Bo Li**<sup>**8**</sup> **, Xingjun Ma**<sup>**1,2,**</sup><sup>_†_</sup> **, Yu-Gang Jiang**<sup>**1,**</sup><sup>_†_</sup> 

1Fudan University, 2Shanghai Innovation Institute, 3City University of Hong Kong 

4Jilin University, 5Singapore Management University, 6Deakin University, 7Tongji University, 8UIUC 

9UC Berkeley, 10Nanyang Technological University, 11Chinese Academy of Sciences, 

12The University of Melbourne, 13Johns Hopkins University 

> _∗_ Equal Contribution, _†_ Corresponding authors 

# **Abstract** 

Embodied Artificial Intelligence (Embodied AI) integrates perception, cognition, planning, and interaction into agents that operate in open-world, safety-critical environments. As these systems gain autonomy and enter domains such as transportation, healthcare, and industrial or assistive robotics, ensuring their safety becomes both technically challenging and socially indispensable. Unlike digital AI systems, embodied agents must act under uncertain sensing, incomplete knowledge, and dynamic human–robot interactions, where failures can directly lead to physical harm. This survey provides a comprehensive and structured review of safety research in embodied AI, examining attacks and defenses across the full embodied pipeline, from perception and cognition to planning, action & interaction, and agentic system. We introduce a multi-level taxonomy that unifies fragmented lines of work and connects embodied-specific safety findings with broader advances in vision, language, and multimodal foundation models. Our review synthesizes insights from over 500 papers spanning adversarial, backdoor, jailbreak, and hardware-level attacks; attack detection, safe training and robust inference; and risk-aware human–agent interaction. This analysis reveals several overlooked challenges, including the fragility of multimodal perception fusion, the instability of planning under jailbreak attacks, and the trustworthiness of human–agent interaction in open-ended scenarios. By organizing the field into a coherent framework and identifying critical research gaps, this survey provides a roadmap for building embodied agents that are not only capable and autonomous but also safe, robust, and reliable in real-world deployment. 

**Correspondence:** xingjunma@fudan.edu.cn; ygj@fudan.edu.cn 

**Website:** https://github.com/x-zheng16/Awesome-Embodied-AI-Safety 

**Key Words:** Embodied AI Safety; Trustworthy Embodied AI; Multimodal Safety; Attacks and Defenses 

1 



**Figure 1** Capability vs. risk duality in embodied AI systems. **Left:** Nested capability layers from perception (innermost) to agentic systems (outermost), with representative embodiments at each level: sensor-only devices (e.g., face-recognition access controls), dialogue robots (e.g., museum guides), autonomous vehicles, robotic arms and humanoids, and future agentic robots with memory and tool use. **Right:** Corresponding safety risks at each layer. As capabilities expand outward, the attack surface grows correspondingly—vulnerabilities at inner layers cascade to outer layers, amplifying risks in more autonomous systems. 

# **1 Introduction** 

Embodied Artificial Intelligence (Embodied AI) seeks to endow autonomous agents with the ability to perceive, reason, plan, and interact with the physical world [366]. Unlike purely digital AI systems, embodied agents operate in dynamic, uncertain, and safety-critical environments such as autonomous driving [262, 355, 521], collaborative robotics [24, 349], smart healthcare [93, 126, 166], and assistive robotics [10, 114]. In these settings, unsafe perception, flawed reasoning, erroneous planning, or unsafe interaction can lead not only to degraded task performance but also to real-world accidents, physical harm, and loss of human trust. 

Recent years have witnessed rapid advances across the embodied AI pipeline [24, 175, 294, 299, 410, 411]. Improvements in perception (e.g., vision, LiDAR, multimodal sensing), cognition (e.g., world modeling, value alignment), planning (e.g., task planning, trajectory optimization), and interaction (e.g., safe control, human–robot collaboration) have expanded the capabilities of embodied agents. However, these capabilities also broaden and complicate the attack surface [194, 392, 522]. Safety challenges that once appeared primarily in digital domains, such as adversarial examples in vision or jailbreak prompts in language models, carry far more severe consequences in physical environments. For instance, small perturbations to a visual sensor may cause an autonomous vehicle to misinterpret a stop sign [81], while maliciously poisoned training data may compromise task planning and produce unsafe trajectories [194]. Misaligned or unpredictable human–agent interactions can further generate behaviors that endanger users directly. 

Despite their growing importance, the safety challenges unique to embodied AI remain underexamined. Existing surveys in AI safety largely focus on digital-only systems such as vision foundation models [260, 261, 385], large language models (LLMs), multimodal large language models (MLLMs) [454], digital agents [72, 98], or Vision-Language-Action models (VLAs) [201]. While these works offer valuable taxonomies of attacks and defenses, they rarely address embodied settings where perception, cognition, planning, and interaction are tightly coupled and must operate under real-world constraints. A comprehensive treatment of embodied AI safety therefore requires not only synthesizing research within each component but also integrating insights from broader AI safety domains that have direct implications for embodied systems. 

**Capability–Risk Duality.** A key organizing principle of this survey is the _capability–risk duality_ : each layer of the embodied pipeline represents not merely a functional component but a _capability expansion_ that introduces corresponding new vulnerabilities, as illustrated in Figure 1. Real-world embodied systems vary in the depth 

2 



<!-- Start of picture text -->
Perception Attack Cognition Attack<br>Spatial Perception Scene<br>Sensor  Understanding<br>Attack<br>(20) Jailbreak Attack<br>Motion Perception Adversarial  (2)<br>Attack<br>Misinterpreting  (76) Spatial Reasoning Incorrect Navigation<br> Security System Road SignsFailures Visual Perception Backdoor Attack(13) EmergingRisks(11) Poor Environment AssessmentDecisions<br>Auditory Perception Semantic processing<br>Backdoor  Emerging<br>Physical Harm  Attack Risks Collisions and<br>During Interaction (12) (6) Inefficient Motion<br>Compromised Trust Control Policy Adversarial Attack Jailbreak Attack(7) Task Planning Safety Mechanism Bypass<br>(25) Adversarial<br>Attack<br>EmergingRisks Backdoor Attack (15)<br>Action Execution (14) (3) Trajectory Planning<br>Human Robot Interaction Instruction Following<br>Action and Interaction Attack Planning Attack<br><!-- End of picture text -->

**Figure 2** Illustration of safety threats and attack surfaces across capability layers of embodied AI systems. 

of this capability stack. At the innermost layer, sensor-only devices such as face-recognition access controls represent the simplest embodied systems, where adversaries can only target perceptual inputs. Adding cognition yields agents like museum guide robots capable of dialogue and scene understanding, opening attack surfaces in reasoning and language comprehension. Incorporating planning enables navigation and decision-making, as in autonomous vehicles, where adversaries can additionally manipulate route planning and trajectory prediction. At the action and interaction layer, robotic arms and humanoid robots gain the ability to physically manipulate their environment, exposing control and human–robot interaction to exploitation. Finally, agentic systems augment all prior capabilities with persistent memory, tool use, and self-evolution, creating the broadest attack surface where compromises at any inner layer can cascade outward. This duality, _deeper capability entails broader risk_ , motivates our layered taxonomy and structures the remainder of this survey: each section addresses both the attacks specific to its capability layer and the pathways through which inner-layer vulnerabilities propagate to outer-layer failures. 

To address this need, we conduct a systematic survey of **safety research in embodied AI** . We propose a multi-level taxonomy that organizes vulnerabilities and defenses across five key components of embodied AI systems: **perception** , **cognition** , **planning** , **action & interaction** , and **agentic systems** . For each component, we categorize attacks and defenses, including adversarial perception, unsafe reasoning, planning under perturbations, unsafe control and interaction, and agentic-level risks such as tool misuse, memory poisoning, and cascading failures, as illustrated in Figure 2. Crucially, we extend our synthesis beyond embodied-specific works to incorporate over **500** papers from traditional AI safety (vision, language, multimodal foundation models), selecting those with clear embodied relevance. Figure 3 presents an overview of different attack and defense techniques and their distribution across the pipeline components. This dual perspective situates embodied AI safety within the broader AI safety ecosystem while highlighting the unique risks that emerge when intelligence is deployed in the physical world. 

Based on the current literature, we identify and summarize the threats posed by various attacks, as shown in Table 1. In **perception** , _adversarial attacks_ introduce subtle perturbations in sensory inputs, such as visual or auditory data, causing misclassifications and leading to incorrect environmental interpretations. **Backdoor attacks** embed hidden triggers in the model that activate malicious behavior when prompted, while **sensor attacks** , such as spoofing and jamming, compromise sensor data, resulting in environmental sensing failures 

3 



<!-- Start of picture text -->
Perception<br>Attack<br>Cognition<br>Planning<br>Action<br>Defense<br>Agentic<br><!-- End of picture text -->

**Figure 3** Overview of representative attack and defense methods across perception, cognition, planning, action, and agentic system layers. The width of the strips is proportional to the number of research works. 

or system shutdowns. These vulnerabilities can lead to misinterpretation of objects, failure to detect obstacles, or navigation errors. In **cognition** , _adversarial attacks_ manipulate reasoning processes, causing the system to make unsafe or incorrect decisions, such as faulty spatial understanding or misinterpretation of context. In **planning** , various attacks, including _adversarial attacks_ on task planning and trajectory planning, **jailbreak attacks** , and **backdoor attacks** , can manipulate the model’s planned actions, leading to unsafe trajectories, collisions, or failure to follow intended goals. In **action & interaction** , _adversarial manipulations_ and **backdoor attacks** can bypass safety mechanisms during human-agent interactions, inducing harmful or unintended behavior, such as violating safety protocols or performing actions that harm users. Finally, in **agentic systems** , threats arise from the agent’s expanded autonomy: _tool misuse_ can lead to harmful code execution or unintended physical actions, **memory poisoning** can corrupt the agent’s experience store to cause persistent unsafe behavior, **memory leakage** can expose private user data and privileged context from agent memory stores, and **cascading failures** can propagate through inner layers when self-evolving agents erode their own alignment. In Table 1, we also categorize the potential real-world dangers caused by these threats. 

**Differences from Existing Surveys.** Prior surveys examine embodied AI safety from complementary perspectives. [429] provides an early analysis of vulnerabilities and attack surfaces but offers limited coverage of defensive strategies. [408] focuses on robustness issues in navigation but does not extend to cognition, manipulation, or human–robot interaction. [346] presents conceptual foundations and system-level safety principles but does not develop detailed attack–defense taxonomies. [18] analyzes world-model safety, particularly predictive failures, while leaving perception, planning, and interaction risks less explored. [255] argues that embodied failures arise from system-level mismatches rather than isolated LLM or CPS flaws, but does not develop component-level attack–defense taxonomies. [393] examines adversarial robustness from a closed-loop propagation perspective, but focuses on adversarial attacks without covering backdoor, jailbreak, or agentic-level threats. [139] surveys security threats and defenses for Embodied LLMs, but scopes narrowly to LLM integration without addressing broader perception or interaction layers. [293] provides a policy-oriented risk taxonomy spanning physical, informational, and social dimensions, but does not analyze specific attack mechanisms or defenses. [404] surveys embodied AI from an IoT perspective with a dual-brain 

4 



<!-- Start of picture text -->
Adversarial Attacks (§ 2.1.1) White-boxBlack-box (9):(19): [495[269] []281[323] []280[81]][[8546]][[376353]][[274153]][[339156]][[257435]][[325245]] [313] [315] [416] [256] [417] [286] [406] [263] [475] [210]<br>Adversarial Defenses (§ 2.1.2) RobustRobust TrainingInference(8):(8): [137[269]][167[189]][234[173]][266[280]][192[65]] [[434314]] [[15225]][499[190]]<br>Visual Perception (§ 2.1)<br>Backdoor Attacks (§ 2.1.3) TrainingData PoisoningManipulation(7): [118 (2): ] [151[508] [465] [450] [215] ] [492] [218] [239]<br>Backdoor Defenses (§ 2.1.4) Robust Training/Inference (4): [17] [74] [88] [285]<br>Adversarial Attacks (§ 2.2.1) White-boxBlack-box (8):(6): [[36735]][[4641] []484[47]][[56213] []506[214] []23[109] [371] ] [150]<br>Auditory Perception (§ 2.2) Adversarial Defenses (§ 2.2.2) Robust Inference (6): [452] [467] [311] [419] [462] [389]<br>Backdoor (§ 2.2.3) Training Manipulation (1): [531]<br>Adversarial Attacks (§ 2.3.1) White-boxBlack-box (10):(17): [[39432]][[365122]][[208142]][[61514] []459[95]][[39354] []63[136] [129] [244] [225] [43] []237[62]][525] [40] [247] [199] [509] [402] [176]<br>Perception (§ 2)<br>Robust Training (18): [497] [333] [487] [116] [2] [186] [478] [361] [312] [48] [49] [496] [519] [224] [390] [172]<br>Spatial Perception (§ 2.3) Adversarial Defenses (§ 2.3.2) [381] [50]<br>Robust Inference (9): [125] [227] [123] [460] [424] [64] [30] [28] [494]<br>Backdoor (§ 2.3.3) Data Poisoning (3): [493] [204] [203]<br>Sensor Attacks (§ 2.4.1) SpoofingJamming (19):(2): [220[324] ][147[444] ] [363] [128] [438] [320] [105] [178] [341] [187] [369] [51] [527] [100] [69] [513] [379] [101] [127]<br>Motion Perception (§ 2.4)<br>Anti-Spoofing (25): [296] [91] [9] [377] [82] [148] [438] [80] [351] [441] [479] [243] [279] [341] [157] [232]<br>Sensor Defenses (§ 2.4.2) [149] [520] [143][310] [403] [233] [162] [322] [41]<br>Anti-Jamming (4): [343] [374] [146] [326]<br>Adversarial Attacks (§ 2.5.1) Digital/PhysicalTypographic (1): (4): [144[]33] [117] [528] [318]<br>Cross-Modal Perception (§ 2.5)<br>Adversarial Defenses (§ 2.5.2) Robust Training/Inference (3): [388] [400] [79]<br>Jailbreak Attacks White-boxBlack-box (1):(1): [[25429]]<br>Instruction Understanding (§ 3.1)<br>Jailbreak Defenses Robust Inference (3): [268] [115] [304]<br>Cognition (§ 3) World Model (§ 3.2) Emerging Risks HallucinationRule Violation(4):(10): [52[206] [37] ][336[13]] [[36418] ] [138] [300] [405] [113] [437] [530] [443]<br>Contextual Risk Mitigation (1): [248]<br>Reasoning (§ 3.3) CoT Hĳacking Attacks (2): [180] [362]<br>Adversarial Attacks (§ 4.1.1) Black-box (1): [145]<br>Jailbreak Attacks (§ 4.1.2) White-boxBlack-box (2):(2): [[308231]][[472249]]<br>Task Planning (§ 4.1)<br>Backdoor Attacks (§ 4.1.3) DataTrainingPoisoningManipulation(1): [222 (2): ] [160] [276]<br>Jailbreak Defenses (§ 4.1.4) Robust Inference (7): [489] [409] [268] [386] [446] [288] [491]<br>Adversarial Attacks (§ 4.2.1) White-boxBlack-box (9):(5): [[73482] []382[34]][[89120] []306[83]][[512488]][428] [16] [228] [344]<br>Planning (§ 4)<br>Trajectory Planning (§ 4.2) Jailbreak Attacks (§ 4.2.2) Black-box (3): [490] [409] [229]<br>Adversarial Defenses (§ 4.2.3) RobustRobust TrainingInference(2):(3): [352[466]][436[27]] [271]<br>Byzantine Faults (§ 4.3.1) Attacks (2): [26] [124]<br>Multi-Agent Planning (§ 4.3) Goal Conflicts (§ 4.3.2) Attacks (1): [14]<br>Potential Defenses (§ 4.3.3) Defenses (5): [193] [331] [184] [99] [330]<br>Adversarial Attacks White-boxBlack-box (7):(17): [104[334] []474[473] []510[412] []258[185] []169[337] []15[54] []401[60]] [504] [392] [168] [164] [140] [246] [399] [433] [445] [481]<br>Robust Training (39): [303] [295] [265] [350] [370] [473] [345] [159] [474] [289] [4] [135] [216] [179] [461] [219]<br>Adversarial Defenses [[463205]] [[112470]] [[338433]] [[107133]] [134] [524] [518] [97] [217] [235] [332] [448] [347] [20] [447] [375] [284] [277] [19]<br>Control (§ 5.1) Robust Inference (6): [414] [252] [236] [119] [130] [273]<br>Backdoor Attacks TrainingData PoisoningManipulation(8): [480 (5): ] [106[387] [12] []53[396] [111] [440] [522] [523] [8]] [469] [431]<br>Action (§ 5) Backdoor Defenses Robust Inference (1): [110]<br>Human-Agent Interaction (§ 5.2) Emerging Risks HandoverTrust ManipulationSafety (7):(4): [270[170] [302] [309] [92] ][5[]533[500] []67] [182] [77]<br>Multi-Agent Collaboration (§ 5.3) Emerging Risks InfectionCollusion(1):(2): [108[307]] [358]<br>Tool Attacks ToolTool CreationManipulation(1): [275 (5): ] [321] [195] [90] [21] [131]<br>Tool Use (§ 6.1)<br>Tool Defenses Defenses (7): [453] [421] [380] [386] [38] [253] [425]<br>Memory Attacks PoisoningLeakage (4):(1): [372[57]][485] [230] [511]<br>Memory (§ 6.2)<br>Agentic System (§ 6) Memory Defenses Defenses (3): [211] [240] [348]<br>Emerging Risks MisalignmentCapability Expansion(2): [319 (1): ] [422[103] ]<br>Self-Evolving (§ 6.3)<br>Embodied Alignment Defenses (6): [130] [305] [327] [470] [282] [181]<br>Cascading Risks (§ 6.4) Emerging Risks Cross-LayerSupply Chain(3):(5): [231[522] [455] [396] [102] [523] ] [238] [154]<br>Embodied AI Safety<br><!-- End of picture text -->

**Figure 4** The roadmap of this survey. 

architecture framework, but treats security and privacy as one component among enabling technologies rather than developing attack–defense taxonomies. In contrast, our survey synthesizes attacks and defenses across the entire embodied pipeline and integrates insights from traditional AI safety to provide a unified, mechanism-oriented understanding of embodied AI safety. Figure 4 provides a roadmap of this survey. 

In summary, the main contributions of this work are: 

5 

**Table 1** Summary of attacks and threats across capability layers of embodied AI. 

|**Capability**<br>**Layer**|**Attack**|**Threat**|**Real-world Danger**|
|---|---|---|---|
|Perception|Adversarial Attack<br>Backdoor Attack<br>Sensor Attack|Misclassification,<br>misdetection,<br>scene misinterpretation<br>Triggered misperception, hidden<br>model manipulation<br>Sensor spoofing, jamming, data cor-<br>ruption|Wrong object recognition, traffic sign errors,<br>surveillance failure<br>Unsafe behavior activation, safety bypass<br>during deployment<br>Navigation failure, loss of situational aware-<br>ness, system malfunction|
|Cognition|Adversarial Attack|Faulty reasoning, scene misunder-<br>standing, context errors|Navigation errors, hazard avoidance failure,<br>unsafe decisions|
|Planning|Adversarial Attack<br>Jailbreak Attack<br>Backdoor Attack|Planning perturbation, trajectory<br>errors<br>Safety constraint bypass, unsafe<br>goal generation<br>Triggered policy manipulation, hid-<br>denplanningbias|Collision risk, unstable motion, unsafe task<br>execution<br>Execution of prohibited actions, violation of<br>safety rules<br>Malicious plans, safety mechanism bypass|
|Action &<br>Interaction|Adversarial Attack<br>Backdoor Attack|Action manipulation, safety guard<br>evasion<br>Triggered harmful actions, hidden<br>interaction flaws|Unsafe human–robot interaction, physical<br>injury risk<br>Malicious responses, loss of control, safety<br>violation|
||Tool / Skill Misuse|Unsafe tool calls, harmful code ex-|Physical damage, unsafe API or actuator|
|Agentic||ecution|commands, skill-driven misbehavior|
|System|Memory Poisoning<br>Memory Leakage|Corrupted memory, unsafe policy<br>update<br>Sensitive memory exposure, data<br>extraction|Repeated unsafe behavior, long-term relia-<br>bility loss<br>Privacy breach, leakage of logs or user data|
||Cascading Failure|Cross-layer<br>error<br>propagation,<br>alignment drift|System-wide failure,<br>uncontrolled self-<br>evolution|



- We present a systematic survey of **safety research in embodied AI** , organizing attacks and defenses into a coherent multi-level taxonomy spanning perception, cognition, planning, action & interaction, and agentic systems. 

- We review over **500** papers, consolidating embodied-specific research with safety-relevant advances in vision, language, and multimodal foundation models. 

- We identify fundamental challenges, open problems, and future research directions, offering a roadmap for developing embodied agents that are not only capable and autonomous but also safe and trustworthy in real-world environments. 

# **2 Perception** 

Perception forms the innermost layer of embodied AI, granting agents the foundational capability to interpret their environment through multiple sensing modalities. At this layer, the attack surface originates at the sensory boundary: adversaries can corrupt what the agent perceives through adversarial perturbations, sensor spoofing, and backdoor triggers. Because perception underpins all outer layers, errors at this stage propagate and amplify throughout the system: a misclassified object leads to flawed reasoning, unsafe plans, and dangerous actions. This section organizes perception by sensing modality: **Visual Perception** (Section 2.1) addresses vulnerabilities in camera-based perception, with emphasis on modern visual encoders (e.g., CLIP, ViT, and SigLIP) used in vision-language models; **Auditory Perception** (Section 2.2) covers attacks on speech recognition and speaker verification systems critical for voice-based human-agent interaction; 

6 

**Table 2** A summary of **adversarial attacks** for **visual perception** . 

|**Attack**|**Method**|**Year**|**Category**|**Subcategory**|**Target Model**|**Dataset**|
|---|---|---|---|---|---|---|
||Melis et al.[269]|2017|White-box|Digital Attack|Object Classifier|iCubWorld|
||Thys et al.[353]|2019|White-box|Digital Attack|Object Detector|Inria|
||Adversarial<br>Overlay[416]|2023|White-box|Digital Attack|Object Detector|PASCAL VOC, ROS Gazebo|
||HitM[417]|2024|White-box|Digital Attack|Object Detector|CARLA, VOC|
||RTAA[153]|2020|White-box|Digital Attack|Single-Object Trac|ker<br>OTB, UAV, VOT|
||TrackPGD[286]|2024|White-box|Digital Attack|Single-Object Trac|ker<br>DAVIS, GOT-10k, UAV, VOT|
||Tracker<br>Hĳacking[156]|2020|White-box|Digital Attack|Multi-Object Track|er<br>BDD|
||Ma et al.[256]|2023|White-box|Digital Attack|Multi-Object Track|er<br>BDD|
||CAA[406]|2024|White-box|Digital Attack|Semantic Segmen<br>tion|ta-<br>Cityscapes, RainCityscapes|
||Uncertainty[263]|2024|White-box|Digital Attack|Semantic Segmen<br>tion|ta-<br>Cityscapes, VOC|
||AnyAttack[475]|2025|White-box|Digital Attack|CLIP Image Encod|er<br>LAION-400M|
||PCFA[315]|2022|White-box|Digital Attack|Optical Flow Esti<br>tor|ma-<br>Sintel, KITTI|
||DARTS[323]|2018|White-box|Physical Attack|Object Classifier|GTSDB, GTSRB|
||RP2[81]|2018|White-box|Physical Attack|Object Classifier|GTSRB, LISA|
|Adil|ShapeShifter[46]|2018|White-box|Physical Attack|Object Detector|Real-world data|
|versara<br>Attack|AdvT[435]|2020|White-box|Physical Attack|Object Detector|Real-world data|
||SLAP[245]|2021|White-box|Physical Attack|Object Detector|Real-world data|
||DRP[313]|2021|White-box|Physical Attack|Object Detector|Comma2k19, LGSVL|
||MFDA[210]|2025|White-box|Physical Attack|Single-Object Trac|ker<br>CARLA|
||AdvTraj[376]|2024|Black-box|Digital Attack|Multi-Object Track|er<br>CARLA|
||Fang et al.[85]|2023|Black-box|Digital Attack|Object Detector|Carlasc, Comma2k19, CULane|
||PB-UAP[325]|2025|Black-box|Digital Attack|Semantic Segmen<br>tion|ta-<br>VOC, Cityscapes|
||ELA[339]|2024|Black-box|Physical Attack|Object Classifier|CARLA|
||CAMOU[495]|2018|Black-box|Physical Attack|Object Detector|Unreal Engine|
||MobilBye[281]|2019|Black-box|Physical Attack|Object Detector|Real-world data|
||SSPA[280]|2020|Black-box|<br>Physical Attack|<br>Object Detector|Web data|
||NS Attack[274]|2024|Black-box|<br>Physical Attack|<br>Object Detector|CARLA|
||ControlLoc[257]|2024|Black-box|Physical Attack|Multi-Object Track|er<br>BDD, KITTI|
||Zhu et al.[526]|2026|White-box|Physical Attack|Object Detector|LLVIP, FLIR|



**Spatial Perception** (Section 2.3) examines threats to 3D understanding including SLAM, depth estimation, pose estimation, and neural scene representations (e.g., NeRF and 3DGS); **Motion Perception** (Section 2.4) addresses vulnerabilities in inertial measurement, GPS, and proprioceptive sensing; and **Cross-Modal Perception** (Section 2.5) discusses attacks on multimodal perception systems and sensor fusion. For each modality, we review attacks, defenses, and evaluation benchmarks. Sensor-level attacks (spoofing and jamming) are integrated within each modality rather than treated separately. 

## **2.1 Visual Perception** 

Visual perception encompasses camera-based tasks such as object classification, object detection (including lane detection), object tracking, semantic segmentation, and video understanding (action recognition, optical flow, and video object segmentation), each critical for embodied downstream tasks. Modern visual encoders, including contrastive vision-language models (e.g., CLIP and SigLIP) and Vision Transformers (ViT), serve as shared perception backbones whose vulnerabilities propagate to all downstream systems. This subsection 

7 

consolidates all visual perception security research: adversarial attacks and defenses that manipulate or protect pixel-level inputs, as well as backdoor attacks and defenses that embed or remove hidden triggers in visual models. We organize the discussion into four parts: **Adversarial Attacks** (Section 2.1.1), **Adversarial Defenses** (Section 2.1.2), **Backdoor Attacks** (Section 2.1.3), and **Backdoor Defenses** (Section 2.1.4). 

### **2.1.1 Adversarial Attacks** 

Adversarial attacks on vision pipelines typically occur in two domains: in the digital space, where they perturb pixel values, and in the physical world, where they manipulate real-world signals (e.g., road signs and flashlights) to deceive perception systems. 

**White-box Attacks** . White-box attacks exploit full model access to craft precise perturbations, organized into digital and physical attack strategies. Digital attacks manipulate inputs directly in the digital space. For object classification, Melis et al. [269] introduced region-constrained perturbations against the iCub robot’s vision pipeline. For object detection, Thys et al. [353] used adversarial patches to conceal detections or degrade localization. Adversarial Overlay [416] proposes real-time attacks, and HitM [417] introduces a human-in-the-middle threat model that intercepts camera data before OS processing. For single-object tracking, RTAA [153] exploits temporal information by leveraging motion and recent predictions across frames. TrackPGD [286] targets Transformer-based trackers specifically. For multi-object tracking, under tracking-by-detection (TBD) and joint-detection-tracking (JDT) paradigms, Tracker Hĳacking [156] exploits sparse-frame perturbations to induce long-term tracking failures. Ma et al.’s attack [256] corrupts the detection stage via adversarial patches. For semantic segmentation, CAA [406] performs multi-task attacks on joint networks. Uncertainty [263] applies loss-weighting based on uncertainty. 

Modern visual encoders introduce new attack surfaces beyond task-specific models. For contrastive visionlanguage encoders such as CLIP and SigLIP, whose compromise cascades to all downstream VLMs and embodied agents, AnyAttack [475] pre-trains a self-supervised perturbation generator on LAION-400M that produces cross-model attacks against CLIP, BLIP, BLIP2, and commercial systems without label supervision. 

Video perception models face temporal adversarial threats absent from single-image models. PCFA [315] targets optical flow models with global perturbations that shift predicted flow toward attacker-chosen targets. 

Physical attacks modify objects or scenes to deceive perception under realistic conditions. For object classification, DARTS [323] and RP2 [81] perform physical attacks by attaching stickers or printing patterns on objects. For object detection, ShapeShifter [46] extended Expectation over Transformation (EoT) to the physical domain. AdvT [435], SLAP [245] and DRP [313] perform physical adversarial attacks on objects or environments by printing patterns on garments, projecting textures onto traffic signs, or disguising patches as road stains. For single-object tracking, MFDA [210] fools SOT models under viewpoint, deformation, and illumination changes. 

**Black-box Attacks** . Black-box attacks operate without model access, relying on transferability, query-based optimization, or surrogate models, organized into digital and physical attack strategies. In the digital domain, for multi-object tracking, AdvTraj [376] confuses the association phase by swapping the attacker’s ID with a target’s ID. For object detection, Fang et al. [85] used Particle Swarm Optimization to perform heuristic searches on lane-like perturbations for lane detection. For semantic segmentation, PB-UAP [325] generates black-box universal perturbations transferable across models. 

In the physical domain, for object classification, ELA [339] predicts traffic-sign poses and trains an RL agent to project adversarial laser patterns in real time. For object detection, CAMOU [495] perturbs vehicle appearances, while MobilBye [281] and SSPA [280] employ optical-based attacks via projecting phantom objects. NS Attack [274] perturbs road appearances to evade detection. For multi-object tracking, ControlLoc [257] searches for optimal patch placements to manipulate objects’ positions and shapes. For visible-thermal detection, Zhu et al. [526] craft a single physical garment with non-overlapping RGB and thermal patterns to fool both modalities at once. 

8 

**Table 3** A summary of **adversarial defenses** for **visual perception** . 

|**Defense**|**Method**|**Year**<br>**Category**|**Subcategory**|**Target Model**<br>**Dataset**|
|---|---|---|---|---|
||Kalin et al.[167]|2021<br>Robust Training|Adversarial Training|<br>Object Classifier<br>VEDAI|
||DSNet[137]|2020<br>Robust Training|Adversarial Training|<br>Object Detector<br>FOD, Foggy Driving|
||IA-YOLO[234]|2022<br>Robust Training|Adversarial Training|<br>Object Detector<br>VOC_Foggy, RTTS|
||BAD-Net[192]|2023<br>Robust Training|Adversarial Training|<br>Object Detector<br>RTTS, VOChaze|
||Blazevic et al.[25|]<br>2025<br>Robust Training|Adversarial Training|<br>Object Detector<br>MetaDrive|
||RP-PGD[499]|2025<br>Robust Training|Adversarial Training|<br>Semantic<br>Seg-<br>mentation<br>ADE20K, VOC, Cityscapes|
||TeCoA[266]|2023<br>Robust Training|Adversarial Training|<br>CLIP Image En-<br>coder<br>ImageNet, 15 ZS datasets|
||Robust CLIP[314|]<br>2024<br>Robust Training|Adversarial Training|<br>CLIP Image En-<br>coder<br>ImageNet, COCO|
||Melis et al.[269]|2017<br>Robust Inference|<br>Input Moderation|Object Classifier<br>iCubWorld|
|Adversarial<br>|AOD-Net[189]|2017<br>Robust Inference|<br>Input Moderation|Object Detector<br>Middlebury, Real-world data|
|Defense|DGFN[173]|2018<br>Robust Inference|<br>Input Moderation|Object Detector<br>KITTI|
||GhostBusters[280|]<br>2020<br>Robust Inference|<br>Input Moderation|Object Detector<br>Real-world data|
||Jia et al.[152]|2024<br>Robust Inference|<br>Input Moderation|Single-Object<br>Tracker<br>UAV|
||SentiNet[65]|2020<br>Robust Inference|<br>Output Moderation|Object Detector<br>ImageNet, LFW, LISA, VGG-<br>Face|
||Xu et al.[434]|2021<br>Robust Inference|<br>Output Moderation|Object Detector<br>TuSimple|
||Li et al.[190]|2025<br>Robust Inference|<br>Output Moderation|Single-Object<br>Tracker<br>LaSOT, OTB, UAV|



### **2.1.2 Adversarial Defenses** 

Visual defenses protect object classification, object detection (including lane detection), tracking, and segmentation pipelines from adversarial manipulation through robust training and robust inference strategies. 

**Robust Training** . Robust training hardens models by incorporating adversarial examples, augmented data, or feature recovery during training. For object classification, Kalin et al. [167] retrained models with visible-light and infrared imagery, guided by adversarial-surface analysis. For object detection, DSNet [137], IA-YOLO [234], and BAD-Net [192] jointly learn visibility enhancement, feature restoration, or dehazing with detection, and Blazevic et al. [25] trained robust lane detection models against adversarial perturbations. For semantic segmentation, RP-PGD [499] employs adversarial training to enhance model robustness. 

**Robust Inference** . Robust inference defends models through input or output moderation. Input moderation detects anomalous inputs, preprocesses signals, restores degraded data, or fuses multimodal information. For object classification, Melis et al. [269] detected and filtered inputs deviating from training distributions in deep feature space. For object detection, AOD-Net [189] provides lightweight dehazing to restore visibility. DGFN [173] fuses camera and LiDAR data with gating mechanisms. GhostBusters [280] deploys four specialized CNNs analyzing various visual features. For single-object tracking, Jia et al. [152] detected attacks using similarity differences in the feature space. Modern visual encoders also require architectureaware defenses. For CLIP-family encoders, TeCoA [266] introduces contrastive adversarial fine-tuning that improves zero-shot robustness. Robust CLIP [314] proposes unsupervised adversarial fine-tuning to ensure that downstream tasks inherit encoder-level robustness. Output moderation verifies model predictions by analyzing output behavior or comparing predictions across transformations. For object detection, SentiNet [65] employs output-based detection by localizing suspicious regions, while Xu et al. [434] applied a CNN to the detected lanes to classify them as real or fake. For single-object tracking, Li et al. [190] compared full- and low-frequency tracking, using the low-frequency branch as a stable reference. 

9 

### **2.1.3 Backdoor Attacks** 

Backdoor attacks on visual perception embed hidden triggers during model training so that the system behaves normally on benign inputs but executes attacker-chosen behaviors when the trigger appears. These attacks target visual models through training manipulation or data poisoning. 

**Training Manipulation** . Training manipulation attacks embed backdoors by manipulating training objectives or procedures. For ViTs, TrojViT [508] injects trojans via RowHammer-based bit-flipping without training-time poisoning, and SWARM [450] targets prompt-tuned ViTs with a switchable backdoor. 

**Data Poisoning** . Data poisoning attacks embed backdoors by injecting triggered samples into training data. Han et al. [118] inserted physical objects as triggers using poison-annotation strategies for object detectors. BadLANE [492] and DBALD [218] embed visual pattern triggers via meta-learning or diffusion-based synthesis for object detectors. 

Modern visual encoders are also vulnerable to backdoor attacks. For vision-language encoders, a single compromised encoder propagates backdoor behavior to all downstream tasks: BadEncoder [151] first demonstrates this supply-chain threat on pre-trained encoders including CLIP, BadCLIP [215] optimizes triggers via dual-embedding guided Bayesian reasoning, and BadVision [239] exploits SSL encoder backdoors to induce visual hallucinations in LVLMs. For ViTs, BadViT [465] shows that self-attention makes ViTs more sensitive to patch-wise triggers than CNNs. 

### **2.1.4 Backdoor Defenses** 

Backdoor defenses for visual perception aim to detect or remove hidden visual triggers implanted during training. Current defense research for task-specific visual backdoor attacks remains limited, highlighting an important open challenge for securing visual perception in embodied systems. 

For modern visual encoders, backdoor defenses must operate at encoder level. For ViTs, Doan et al. [74] exploited patch-transformation responses to detect triggers without training data access. For CLIP-family encoders, CleanCLIP [17] re-aligns modality representations via multimodal contrastive fine-tuning to weaken backdoor associations, DECREE [88] detects backdoors in pre-trained encoders without classifier headers or input labels, and BDetCLIP [285] enables efficient test-time backdoor detection via contrastive prompting. 

## **2.2 Auditory Perception** 

Auditory perception supports human-robot interaction and voice-based control through speech recognizers, which convert spoken language into text, and speaker verifiers, which authenticate speaker identity based on voice characteristics. This subsection consolidates all auditory perception security research, organized into three parts: **Adversarial Attacks** (Section 2.2.1), **Adversarial Defenses** (Section 2.2.2), and **Backdoor Attacks and Defenses** (Section 2.2.3). 

### **2.2.1 Adversarial Attacks** 

Adversarial attacks on auditory perception operate in the digital space by perturbing audio waveforms and in the physical space by manipulating signals (e.g., voice injection and speaker spoofing). 

**White-box Attacks** . In the physical space, for speech recognizers, Carlini et al. [35] converted audio commands into forms unintelligible to humans. CommanderSong [464] embeds perturbations into songs. Metamorph [47] employs background-like audio perturbations, while SpecPatch [109] employs audio spectrogram patches. For speaker verifiers, Li et al. [213] incorporated Room Impulse Response to maintain effectiveness under over-the-air playback. For the joint speech recognizers and speaker verifiers, AdvPulse [214] designs subsecond perturbations. 

**Black-box Attacks** . In the digital space, TSMAE [150] adjusts playback speed to attack speech recognizers. Occam [506] introduces decision-only adversarial examples for cloud APIs. In the physical space, for speech 

10 

**Table 4** A summary of **adversarial** attacks and defenses for **auditory perception** . 

|**Attack/Defen**|**se**<br>**Method**|**Year**|**Category**|**Subcategory**|**Target M**|**odel**|**Dataset**||
|---|---|---|---|---|---|---|---|---|
||Carlini et al.[35]|2016|White-box|Physical Attack|Speech<br>nizer|Reco|g-<br>Custom dataset||
||CommanderSong[46|4]<br>2018|White-box|Physical Attack|Speech<br>nizer|Reco|g-<br>Custom dataset||
||Metamorph[47]|2020|White-box|Physical Attack|Speech<br>nizer|Reco|g-<br>AIR,<br>Common<br>MARDY|Voice,|
||SpecPatch[109]|2022|White-box|Physical Attack|Speech<br>nizer|Reco|g-<br>TIMIT||
||Li et al.[213]|2020|White-box|Physical Attack|Speech V|erifier|CSTR VCTK Corpu|s|
||AdvPulse[214]|2020|White-box|Physical Attack|Speech R|ec./Ve|r.<br>CSTR VCTK Corpu<br>Commands|s, Voice|
||TSMAE[150]|2024|Black-box|Digital Attack|Speech<br>nizer|Reco|g-<br>CSTR VCTK Corp<br>tom dataset|us, Cus-|
||Occam[506]|2021|Black-box|Digital Attack|Speech R|ec./Ve|r.<br>Common<br>Voice,<br>riSpeech, VoxCeleb|Lib-|
||Cocaine Noodles[367|]<br>2015|Black-box|Physical Attack|Speech<br>nizer|Reco|g-<br>Custom dataset||
|Adversarial<br>Attack|Wang et al.[389]|2020|Black-box|Physical Attack|Speech<br>nizer|Reco|g-<br>Custom dataset||
||Devil’s Whisper[56]|2020|Black-box|Physical Attack|Speech<br>nizer|Reco|g-<br>CommanderSong d|ataset|
||BarrierBypass[371]|2023|Black-box|Physical Attack|Speech<br>nizer|Reco|g-<br>Custom dataset||
||Vaspy[484]|2019|Black-box|Physical Attack|Speech V|erifier|Custom dataset||
||Bilika et al.[23]|2023|Black-box|Physical Attack|Speech V|erifier|Custom dataset||
||Abdullah et al.[1]|2019|Black-box|Physical Attack|Speech R|ec./Ve|r.<br>LibriSpeech, TIMIT||
||Yang et al.[452]|2018|Robust Inference|Input Moderation|Speech<br>nizer|Reco|g-<br>Common Voice, LI|BRIS|
||Samizade et al.[311]|2020|Robust Inference|Input Moderation|Speech<br>nizer|Reco|g-<br>Common Voice,<br>Commands|Speech|
||AudioPure[419]|2023|Robust Inference|Input Moderation|Speech<br>nizer|Reco|g-<br>Qualcomm<br>K<br>Speech|eyword|
|Adversarial|AntiFake[462]|2023|Robust Inference|Input Moderation|Speech Vi|erifier|CSTR VCTK, Libri<br>TIMIT|Speech,|
|Defense|Yang et al.[452]|2018|Robust Inference|Output Moderatio|n<br>Speech<br>nizer|Reco|g-<br>Common Voice, LI|BRIS|
||MVP-EARS[467]|2019|Robust Inference|Output Moderatio|n<br>Speech<br>nizer|Reco|g-<br>Common Voice, <br>dataset|Custom|



11 

recognizers, BarrierBypass [371] injects commands through physical barriers. Cocaine Noodles [367] and Abdullah et al. [1] generated mangled inputs that are unintelligible to humans but still recognized by machines. Devil’s Whisper [56] crafts adversarial examples by pairing a query-based substitute with a stronger white-box recognizer. Wang et al. [389] modulated the signals to compensate for the distortion in the frequency domain. For speaker verifiers, Vaspy [484] synthesizes activation keywords via speech recognition and voice cloning. Bilika et al. [23] demonstrated practical feasibility in real-world scenarios. 

### **2.2.2 Adversarial Defenses** 

Auditory defenses protect speech recognizer and speaker verifier systems from adversarial perturbations through robust inference strategies. 

**Robust Inference** . For input moderation of speech recognizers, Samizade et al. [311] extracted MFCC features and classified benign and adversarial samples using CNNs. Yang et al. [452] explored input preprocessing techniques, including perturbation, compression, quantization, smoothing, reconstruction, and downsampling. AudioPure [419] employs diffusion models to purify and restore input signals. For speaker verifiers, AntiFake [462] embeds protective perturbations into audio to prevent voice cloning and forgery. For output moderation of speech recognizers, Yang et al.’s approach [452] compares transcription consistency between audio segments and complete audio. MVP-EARS [467] uses multiple models for cross-verification. 

### **2.2.3 Backdoor Attacks and Defenses** 

Backdoor research on auditory perception remains nascent. TrojanModel [531] inserts backdoors into acoustic models for speech recognizers via training manipulation, but no dedicated defense has been proposed, highlighting an important open challenge for securing speech-based embodied systems. 

## **2.3 Spatial Perception** 

Spatial perception enables embodied agents to build, maintain, and reason about 3D representations of their environment for navigation, manipulation, and obstacle avoidance. It encompasses point cloud classification, 3D object detection and tracking, trajectory prediction, depth and pose estimation, SLAM, and neural scene representations (NeRF, 3DGS). This subsection consolidates all spatial perception security research, organized into three parts: **Adversarial Attacks** (Section 2.3.1), **Adversarial Defenses** (Section 2.3.2), and **Backdoor Attacks and Defenses** (Section 2.3.3). 

### **2.3.1 Adversarial Attacks** 

Adversarial attacks on spatial perception models perturb point clouds, depth maps, or neural scene representations in the digital space, or manipulate 3D object geometries, LiDAR signals, or camera inputs in the physical space to disrupt detection, localization, and navigation. 

**White-box Attacks** . White-box attacks exploit full model access to craft precise perturbations, organized into digital and physical attack strategies. In the digital domain, for 3D object detectors, FLAT [208] manipulates the vehicle trajectory to affect LiDAR motion compensation. SlowLiDAR [225] introduces slow-acting perturbations, causing delayed failures. Zheng et al. [509] leveraged smoke-like perturbations to interfere with sensing, and Wang et al. [402] utilized saliency maps to identify critical points before optimizing perturbations. For 3D object trackers, Cheng et al.’s method [61] crafts universal perturbations, and TAN [237] crafts transferable perturbations. For SLAM systems, Yoshida et al. [459] applied small, well-timed perturbations to LiDAR point clouds to disrupt scan matching and degrade map consistency, leading to accumulating localization errors. For scene representation models, Horváth and Józsa [129] demonstrated that NeRFs can be subverted by carefully perturbed input views to render photorealistic but falsified scenes, and Poison-Splat [247] introduces a data-poisoning attack on 3DGS that corrupts adaptive density control, causing denial-of-service through excessive memory and compute usage. In the physical domain, for 3D object detectors, LiDAR-Adv [32] and Tu et al.’s attack [365] optimize adversarial 3D mesh 

12 

**Table 5** A summary of **adversarial attacks** for **spatial perception** . 

|**Attack**|**Method**|**Year**|**Category**|**Subcategory**|**Target Model**<br>**Dataset**|
|---|---|---|---|---|---|
||FLAT[208]|2021|White-box|Digital Attack|3D Object Detec-<br>tor<br>nuScenes|
||SlowLiDAR[225]|2023|White-box|Digital Attack|3D Object Detec-<br>tor<br>KITTI|
||Zheng et al.[509]|2025|White-box|Digital Attack|3D Object Detec-<br>tor<br>KITTI, nuScenes|
||Wang et al.[402]|2025|White-box|Digital Attack|3D Object Detec-<br>tor<br>KITTI, Waymo|
||Cheng et al.[61]|2021|White-box|Digital Attack|3D Object Tracker<br>KITTI|
||TAN[237]|2023|White-box|Digital Attack|3D Object Tracker<br>KITTI|
||Yoshida et al. [459]|2022|White-box|Digital Attack|SLAM (LiDAR)<br>Self-constructed data|
||Horváth<br>and<br>Józsa [129]|2023|White-box|Digital Attack|NeRF Navigator<br>LLFF|
||Poison-Splat [247]|2024|White-box|Digital Attack|3DGS Navigator<br>NeRF-Synthetic,<br>Mip-<br>NeRF360|
||LiDAR-Adv[32]|2019|White-box|Physical Attack|3D Object Detec-<br>tor<br>Real-world data|
||Tu et al.[365]|2020|White-box|Physical Attack|3D Object Detec-<br>tor<br>KITTI|
||AE-Morpher[525]|2024|White-box|Physical Attack|3D Object Detec-<br>tor<br>Custom dataset, SVL simu-<br>lator|
||Adv3D [199]|2024|White-box|Physical Attack|3D Object Detec-<br>tor<br>nuScenes|
||ShadowHack[176]|2025|White-box|Physical Attack|3D Object Detec-<br>tor<br>AWSIM simulator|
||Cheng et al. [63]|2022|White-box|Physical Attack|Depth Estimator<br>KITTI|
||Chawla et al. [39]|2022|White-box|Physical Attack|Pose Estimator<br>KITTI odometry|
||AoR [40]|2024|White-box|Physical Attack|SLAM (Visual)<br>KITTI, Oxford RobotCar,<br>|
||||||4Seasons|
|Adversarial<br>Attack|Hau et al.[122]<br>|2021|Black-box|Digital Attack|3D Object Detec-<br>tor<br>KITTI|
||TAPG[354]|2024|Black-box|Digital Attack|3D Object Tracker<br>KITTI Tracking, nuScenes|
||Cheng et al.[62]|2025|Black-box|Digital Attack|3D Object Tracker<br>KITTI, nuScenes, Waymo|
||Wang et al. [373]|2024|Black-box|Digital Attack|NeRF Navigator<br>LLFF-C, Blender-C|
||SpotAttack[136]|2024|Black-box|Physical Attack|3D Object Detec-<br>tor<br>MATLAB simulator|
||LiDAttack[43]|2025|Black-box|Physical Attack|3D Object Detec-<br>Custom<br>dataset,<br>KITTI,|
||||||tor<br>nuScenes|
||ICSL Attack [394]|2021|Black-box|Physical Attack|Camera<br>Bosch Night, KITTI|
||DoubleStar [514]|2022|Black-box|Physical Attack|Stereo Depth<br>Self-constructed data|
||<br>Ikram et al. [142]|2022|Black-box|<br>Physical Attack|<br>SLAM (Visual)<br>Manhattan,<br>Intel,<br>MIT,<br>Garage|
||Fukunaga et al. [95]|2024|Black-box|Physical Attack|LiDAR SLAM<br>Self-constructed data|
||Lou et al. [244]|2024|Black-box|Physical Attack|Trajectory Predic-<br>tor<br>nuScenes, Real world|



13 

geometries under physical constraints. AE-Morpher [525] generates adversarial meshes with morphing constraints. Adv3D [199] embeds adversarial objects directly as NeRFs, enabling transferable and contact-free perturbations. ShadowHack [176] exploits optimized planar materials to manipulate shadow patterns. For depth estimation, Cheng et al. [63] optimized physical adversarial patches that bias monocular depth estimators. For pose estimation, Chawla et al. [39] crafted patches that yield large trajectory errors. For visual SLAM, AoR [40] uses adversarial patches to trigger false loop closures, producing severe localization drift. 

**Black-box Attacks** . In the digital space, for 3D object detectors, Hau et al. [122] forced the sensor to record injected points, thereby pushing the genuine points outside the object’s bounding box. For 3D object trackers, TAPG [354] and Cheng et al. [62] optimized black-box attacks via transfer-based and explainabilityguided methods, respectively. For NeRF-based navigation, Wang et al. [373] benchmarked NeRF navigators under visual corruptions. In the physical domain, for 3D object detectors, SpotAttack [136] employs a genetic algorithm-based global search to optimize non-reflective adversarial spots, while LiDAttack [43] combines global search with local refinement for covert attacks. For camera-based systems, ICSL Attack [394] creates ghost traffic signals using infrared projection invisible to humans. For stereo depth estimation, DoubleStar [514] uses long-range, synchronized light patterns to exploit stereo-matching artifacts and fabricate obstacles for drones. For visual SLAM, Ikram et al. [142] employed duplicated textured regions to trigger perceptual aliasing and induce localization drift. For LiDAR SLAM, Fukunaga et al. [95] injected simple, well-timed points into LiDAR streams to disrupt scan matching. For trajectory predictors, Lou et al. [244] introduced the first physical-world attack on trajectory prediction via LiDAR-induced deceptions, employing a two-stage framework that identifies velocity-insensitive state perturbations and matches them to feasible object locations. 

### **2.3.2 Adversarial Defenses** 

Spatial defenses protect point cloud classifiers, 3D object detectors, SLAM systems, and neural scene representations from adversarial perturbations through robust training and robust inference strategies. 

**Robust Training** . Robust training strengthens spatial perception models by exposing them to adversarial examples, augmented data, or physical constraints during the training process. We refer to adversarial training as a framework where training data is augmented by natural perturbations (e.g., weather, fog, crash simulations) or adversarial perturbations (e.g., gradient-based attacks) to improve model robustness under distribution shift and adversarial manipulation. For point cloud classifiers, Defense-PointNet [497], Sun et al.’s work [333], and PointCutMix [478] employ robust training with data augmentation or perturbation strategies. For 3D object detectors, Hahner et al. [116] introduced LiDAR fog simulation and augmentation techniques. 3D-VField [186] learns vector fields for adversarial augmentation, BAFT [496] and DART [381] use optimized perturbation strategies, and LISA [172] improves robustness via LiDAR-specific augmentation. 

Beyond adversarial training, spatial perception benefits from multi-modal fusion, scene augmentation, environment augmentation, formal safety methods, and risk-aware planning. AcousticFusion [487] fuses auditory cues with visual SLAM to stabilize localization under motion and scene changes, and Wang et al. [390] developed a cooperative safety system fusing multi-camera 3D inputs for dynamic human detection and real-time safety-zone enforcement. Sang et al. [312] proposed systematic scene augmentation that procedurally varies layouts, objects, and states to improve generalization. Adamkiewicz et al. [2] achieved collision-free navigation in NeRF-modeled environments, and Splat-Nav [50] demonstrate safe navigation using Gaussian Splatting. Tong et al. [361] paired predictive NeRF rendering with CBF filtering, CATNIPS [48] reinterprets NeRF densities for collision-probability estimation, Zhou et al. [519] coupled visual-inertial SLAM with control barrier functions (CBFs), and SAFER-Splat [49] embeds CBFs over Gaussian Splatting primitives. RaEM [224] introduces risk-aware view acquisition that prioritizes safety-critical regions. 

**Robust Inference** . Input moderation for spatial perception models detects anomalous inputs, preprocesses point clouds, or restores degraded data before inference. For point cloud classifiers, PointGuard [227] provides certified robustness guarantees. For 3D object detectors, WeatherNet [125] is trained to remove noise induced by bad weather. Shadow-Catcher [123] and LOP [424] detect adversarial point clouds via physical invariants 

14 

**Table 6** A summary of **adversarial defenses** for **spatial perception** . 

|**Defense**|**Method**|**Year**|**Category**|**Subcategory**|**Target Model**<br>**Dataset**|
|---|---|---|---|---|---|
||Defense-<br>PointNet[497]|2019|Robust Training|Adversarial <br>ing|Train-<br>Point Cloud Clas-<br>sifier<br>ShapeNet|
||Sun et al.[333]|2021|Robust Training|Adversarial <br>ing|Train-<br>Point Cloud Clas-<br>sifier<br>ModelNet, ScanObjectNN|
||PointCutMix[478]|2022|Robust Training|Adversarial <br>ing|Train-<br>Point Cloud Clas-<br>sifier<br>ModelNet, ScanObjectNN|
||Hahner et al.[116]|2021|Robust Training|Adversarial <br>ing|Train-<br>3D Object Detec-<br>tor<br>KITTI|
||3D-VField[186]|2022|Robust Training|Adversarial <br>ing|Train-<br>3D Object Detec-<br>tor<br>CrashD, KITTI, Waymo|
||BAFT[496]|2024|Robust Training|Adversarial <br>ing|Train-<br>3D Object Detec-<br>tor<br>KITTI, Waymo|
||DART[381]|2025|Robust Training|Adversarial <br>ing|Train-<br>3D Object Detec-<br>tor<br>KITTI|
||LISA[172]|2025|Robust Training|Adversarial <br>ing|Train-<br>3D Object Detec-<br>tor<br>KITTI, Waymo|
||AcousticFusion [487|]<br>2021|Robust Training|Multi-Moda<br>sion|l<br>Fu-<br>SLAM<br>Azure Kinect audio and<br>RGB-D|
||Wang et al. [390]|2024|Robust Training|Multi-Moda<br>sion|l<br>Fu-<br>Safety System<br>Self-constructed data|
||Sang et al. [312]|2023|Robust Training|Scene<br>Aug<br>tion|menta-<br>Scene<br>Under-<br>standing<br>iGibson|
||Adamkiewicz et al. [|2]<br>2022|Robust Training|Environmen<br>mentation|t Aug-<br>NeRF Navigator<br>Self-constructed data|
||Splat-Nav [50]|2025|Robust Training|Environmen<br>mentation|t Aug-<br>3DGS Navigator<br>Stonehenge, Statues, Flight-<br>room|
||Tong et al. [361]|2022|Robust Training|Formal<br>Methods|Safety<br>NeRF Navigator<br>Replica Dataset|
||CATNIPS [48]|2024|Robust Training|Formal<br>Methods|Safety<br>Navigation<br>Stonehenge, Statues, Flight-<br>room|
||Zhou et al. [519]|2024|Robust Training|Formal<br>Methods|Safety<br>SLAM + Control<br>Self-constructed data|
||SAFER-Splat [49]|2024|Robust Training|Formal<br>Methods|Safety<br>3DGS Navigator<br>Self-constructed data|
||RaEM [224]|2024|Robust Training|Risk-Aware<br>ning|Plan-<br>Active Perception<br>Matterport3D|
||PointGuard[227]|2021|Robust Inference|Input Moder|ation<br>Point Cloud Clas-<br>sifier<br>ModelNet40, ScanNet|
|Adversarial|WeatherNet[125]|2020|Robust Inference|Input Moder|ation<br>3D Object Detec-<br>tor<br>Chamber & road(custom)|
|Defense|Shadow-<br>Catcher[123]|2021|Robust Inference|Input Moder|ation<br>3D Object Detec-<br>tor<br>KITTI|
||LOP[424]|2023|Robust Inference|Input Moder|ation<br>3D Object Detec-<br>tor<br>KITTI, LGSVL simulator|
||ADoPT[64]|2023|Robust Inference|Input Moder|ation<br>3D Object Detec-<br>tor<br>nuScenes|
||LiDARPure[30]|2024|Robust Inference|Input Moder|ation<br>3D Object Detec-<br>tor<br>KITTI|
||Zhang et al. [494]|2025|Robust Inference|Input Moder|ation<br>3D Object Detec-<br>tor<br>nuScenes, KITTI|
||Brunke et al. [28]|2025|Robust Inference|Input Moder|ation<br>Scene<br>Under-<br>standing<br>ScanNet200,<br>Self-<br>constructed data|
||3D-TC2[460]|2021|Robust Inference|Output Mod|eration<br>3D Object Detec-<br>tor<br>nuScenes|
||ViewFool [75]|2022|Robust Inference|Output Mod|eration<br>Object Classifier<br>BlenderKit, Objectron|



15 

**Table 7** A summary of **backdoor** attacks and defenses for **embodied perception** . 

|**Attack/Def**|**ense**<br>**Method**|**Year**|**Category**|**Subcategory**|**Target**|**Model**<br>**Dataset**|
|---|---|---|---|---|---|---|
||TrojViT[508]|2023|Training Manipul<br>tion|a-<br>Bit-Flipping|Vision<br>former|Trans-<br>ImageNet|
||SWARM[450]|2024|Training Manipul<br>tion|a-<br>Prompt Poisoning|Vision<br>former|Trans-<br>CIFAR-100, ImageNet|
||TrojanModel[531]|2023|Training Manipul<br>tion|a-<br>Trigger Injection|Speech<br>nizer|Recog-<br>Google Speech Commands|
||Han et al.[118]|2022|Data Poisoning|Physical Object|Object D|etector<br>TuSimple|
||BadLANE[492]|2024|Data Poisoning|Visual Pattern|Object D|etector<br>CULane, TuSimple|
||DBALD[218]|2025|Data Poisoning|Visual Pattern|Object D|etector<br>CULane, TuSimple|
||BadEncoder[151]|2022|Data Poisoning|Embedding Poison<br>ing|-<br>CLIP I<br>coder|mage En-<br>CIFAR-10, STL-10, SVHN|
||BadCLIP[215]|2024|Data Poisoning|Embedding Poison<br>ing|-<br>CLIP I<br>coder|mage En-<br>ImageNet, 11 ZS datasets|
||BadVision[239]|2025|Data Poisoning|Embedding Poison<br>|-<br>CLIP I<br>|mage En-<br>COCO, VQA-v2|
|Backdoor||||ing|coder||
|Attack|BadViT[465]|2023|Data Poisoning|Attention Manipu<br>lation|-<br>Vision<br>former|Trans-<br>CIFAR-10, ImageNet|
||Zhang et al.[493]|2022|Data Poisoning|BEV Trigger|3D Obje<br>tor|ct Detec-<br>KITTI|
||BadLiDet[204]|2023|Data Poisoning|Point Perturbation|3D Obje<br>tor|ct Detec-<br>KITTI, nuScenes|
||BadLiSeg[203]|2023|Data Poisoning|Spoofed Pattern|3D Segm|entation<br>SemanticKITTI|
||Doan et al.[74]|2023|Robust Inference|Patch Processing|Vision<br>former|Trans-<br>CIFAR-10, ImageNet|
||CleanCLIP[17]|2023|Robust Training|Fine-Tuning|CLIP I<br>coder|mage En-<br>ImageNet, 8 ZS datasets|
|Backdoor<br>Defense|DECREE[88]|2023|Robust Inference|Detection|CLIP I<br>coder|mage En-<br>CIFAR-10, ImageNet, STL-<br>10|
||BDetCLIP[285]|2025|Robust Inference|Test-Time Detectio|n<br>CLIP I<br>coder|mage En-<br>ImageNet, 11 ZS datasets|



such as 3D shadows and depth-density relations. ADoPT [64] leverages temporal consistency for abnormal input detection. LiDARPure [30] employs diffusion models to purify input point clouds. Zhang et al. [494] proposed the first real-time defense against object-based LiDAR attacks, employing a generative model positioned between sensing and perception to identify and remove adversarial points from suspicious regions in point clouds. For scene understanding, Brunke et al. [28] introduced a semantic safety filter integrating 3D semantic maps with LLM reasoning, compiling abstract language-grounded rules into CBFs that enforce both geometric and semantic safety. For output moderation, 3D-TC2 [460] verifies predictions of 3D object detectors via temporal consistency across frames. ViewFool [75] employs NeRF to systematically identify failure-inducing viewpoints for robustness assessment of object classifiers. 

### **2.3.3 Backdoor Attacks and Defenses** 

Backdoor attacks on spatial perception target 3D object detectors and LiDAR segmentation through data poisoning. Zhang et al. [493] and BadLiDet [204] demonstrate pixel-level trigger injection in bird’s-eye-view representations and imperceptible point-level perturbations for 3D object detectors, while BadLiSeg [203] embeds backdoors in LiDAR segmentation via crafted spoofed patterns. No dedicated defense has been proposed for spatial backdoors, an important open challenge for securing 3D perception in embodied systems. 

16 

**Table 8** A summary of **sensor attacks** for **motion perception** . RF: Radio Frequency; EM: Electromagnetic. 

|**Attack**|**Method**|**Year**|**Category**|**Subcategory**|**Target Sensor**|**Dataset**|
|---|---|---|---|---|---|---|
||Lenhart et al.[187]|2021|Spoofing|Replay Spoofing|GNSS|real-world data|
||Wang et al.[379]|2025|Spoofing|Replay Spoofing|GNSS|ESA, real-world data|
||Horton et al.[128]|2018|Spoofing|Generative Spoofing|GNSS|real-world data|
||FusionRipper[320]|2020|Spoofing|Generative Spoofing|GNSS|Apollo Data, KAIST Com-<br>plex Urban|
||Dasgupta et al.[69]|2024|Spoofing|Generative Spoofing|GNSS|custom dataset|
||Zhong et al.[513]|2025|Spoofing|Generative Spoofing|GNSS|real-world data|
||Son et al.[324]|2015|Spoofing|Acoustic Injection|IMU|real-world data|
||WALNUT[363]|2017|Spoofing|Acoustic Injection|IMU|real-world data|
||KITE[100]|2023|Spoofing|Acoustic Injection|IMU|custom dataset, real-world<br>data|
||Yan et al.[444]|2016|Spoofing|Acoustic Injection|Ultrasonic Rang<br>ing|-<br>real-world data|
||Xu et al.[438]|2018|Spoofing|Acoustic Injection|Ultrasonic Rang<br>ing|-<br>real-world data|
|Sensor<br>Attack|Gluck et al.[105]|2020|Spoofing|Acoustic Injection|Ultrasonic Rang<br>ing|-<br>real-world data|
||Sun et al.[341]|2021|Spoofing|RF Injection|mmWave Radar|real-world data|
||Komissarov et al.[178|]<br>2021|Spoofing|RF Injection|mmWave Radar|real-world data|
||mmSpoof[369]|2023|Spoofing|RF Injection|mmWave Radar|real-world data|
||MetaWave[51]|2023|Spoofing|Physical Manipulation|mmWave Radar|real-world data|
||TileMask[527]|2023|Spoofing|Physical Manipulation|mmWave Radar|real-world data|
||mmHide[101]|2025|Spoofing|Physical Manipulation|mmWave Radar|real-world data|
||Lim et al.[220]|2018|Jamming|Acoustic Interference|Ultrasonic Rang<br>ing|-<br>real-world data|
||Jang et al.[147]|2023|Jamming|EM Interference|IMU|custom dataset, real-world<br>data|



## **2.4 Motion Perception** 

Motion perception enables embodied agents to estimate pose, velocity, and trajectory through inertial measurement units (IMUs), visual and LiDAR odometry, Global Navigation Satellite System (GNSS) receivers, and simultaneous localization and mapping (SLAM) pipelines. Compromised motion perception leads to dangerous physical behavior: erroneous position estimates cause collision, drift, or loss of navigation, while corrupted pose estimation destabilizes control loops in drones, ground robots, and autonomous vehicles. We organize the discussion into two parts: **Sensor Attacks** (Section 2.4.1) cover IMU-based perception attacks, localization and odometry attacks, and sensor-level spoofing and jamming of GNSS, IMU, ultrasonic, and mmWave radar systems; and **Sensor Defenses** (Section 2.4.2) protect motion estimation through anomaly detection, cross-sensor verification, robust state estimation, and anti-spoofing/anti-jamming mechanisms. 

### **2.4.1 Sensor Attacks** 

Sensor attacks on motion perception manipulate raw sensor signals before data reaches perception algorithms, exploiting hardware vulnerabilities, signal-processing pipelines, or physical-layer characteristics. These attacks compromise the integrity of raw measurements through physical injection and interference to achieve spoofing (deception) or jamming (disruption) goals. 

**Spoofing** . Spoofing covers adversarial techniques that manipulate sensor inputs by injecting or presenting false, yet physically plausible, signals, inducing erroneous measurements or misleading perception. 

17 

For GNSS, replay spoofing captures and retransmits authentic signals with intentional delay. Lenhart et al. [187] demonstrated long-range real-time relay systems using commercial software-defined radios (SDRs), and Wang et al. [379] exposed vulnerabilities in Galileo’s OSNMA via manipulated time synchronization. 

Generative spoofing synthesizes counterfeit yet realistic GNSS signals. Horton and Ranganathan [128] leveraged low-cost SDR platforms to generate spoofing signals; Shen et al. [320] crafted fusion-aware perturbations to mislead integrated navigation systems; Dasgupta et al. [69] devised slow-drift attacks; and Zhong et al. [513] analyzed perturbations against integrated navigation. 

Acoustic injection exploits resonance in inertial sensors by emitting ultrasonic or audible signals. For IMUs, Son et al. [324] showed that single-tone acoustic excitation can induce gyroscope deviations. WALNUT [363] combines acoustic induction with ADC aliasing to trigger false readings, and KITE [100] refines resonanceresponse modeling for precise control. For ultrasonic ranging systems, Yan et al. [444], Xu et al. [438], and Gluck et al. [105] showed that crafted acoustic echoes can spoof distance measurements. 

RF injection targets radio-frequency sensors such as mmWave radar by introducing synchronized or tailored electromagnetic signals. Sun et al. [341] and Komissarov and Wool [178] injected synchronized RF signals to manipulate radar point clouds, while Vennam et al. [369] synthesized customized spoofing waveforms to generate deceptive objects. 

Physical manipulation involves placing adversarial objects or engineered surfaces in the environment to passively spoof sensors. For mmWave radar, MetaWave [51], TileMask [527], and mmHide [101] employ metamaterial surface patterns to control radar reflections. 

**Jamming** . Jamming attacks disrupt or block legitimate sensor signals through interference, thereby degrading or completely disabling sensor functionality. These attacks exploit physical-layer vulnerabilities by overwhelming or corrupting the sensing modality with high-energy or carefully crafted noise across acoustic, electromagnetic, or optical domains. 

Acoustic interference employs high-intensity sound to jam ultrasonic sensors. For ultrasonic ranging, Lim et al. [220] demonstrated that high-power acoustic jamming can cause missed detections and destabilize autonomous control policies. Electromagnetic interference disrupts sensor operation through radiated or conducted RF noise. For IMUs, Jang et al. [147] presented a remote electromagnetic injection attack that corrupts communication between the IMU and flight controller, leading to system failure. 

### **2.4.2 Sensor Defenses** 

Defenses for motion perception apply anti-spoofing and anti-jamming mechanisms to detect and recover from corrupted sensor signals. 

**Anti-Spoofing Defenses** . Anti-spoofing defenses detect, authenticate, and mitigate forged signals through three strategies: Detection, Authentication, and Mitigation. Detection identifies malicious signals or anomalous sensor readings by analyzing inconsistencies in signal characteristics, sensor outputs, or crossmodal correlations. 

For GNSS, Falco et al. [82] used dual-antenna double-difference dispersion to detect spatially inconsistent signals. Crowd-GPS-Sec [148] analyzes temporal and spatial inconsistencies across a crowd of devices to identify outliers. DeepSIM [441] uses Siamese networks to match ground-level imagery with satellite maps for consistency verification. DeepPOSE [157] reconstructs vehicle speed and trajectory using ConvLSTM to detect implausible motion patterns. Iqbal et al. [143] introduced a VAE-WGAN framework for zero-day spoofing detection. PADS [233] fuses GNSS with Wi-Fi and cellular data to improve robustness. Jin et al. [162] employed anti-jamming antenna arrays coupled with LightGBM for real-time spoofing classification. 

For IMU, SDI [351] introduces cross-sensor consistency checks, Liu et al. [232] localized acoustic sources via MLPs, and CPD-MhIMU [310] deploys heterogeneous IMUs with adaptive EKF fusion. For ultrasonic ranging, Xu et al. [438] introduced physical shift authentication. SoundFence [243] randomizes pulse 

18 

**Table 9** A summary of **sensor defenses** for **motion perception** . 

|**Defense**|**Method**|**Year**|**Category**|**Subcategory**|**Target Sensor**|**Dataset**|
|---|---|---|---|---|---|---|
||Xu et al.[438]|2018|Anti-Spoofing|Detection|Ultrasonic Ran<br>ing|g-<br>real-world data|
||SoundFence[243]|2021|Anti-Spoofing|Detection|Ultrasonic Ran<br>ing|g-<br>real-world data|
||SecureTrack[322]|2025|Anti-Spoofing|Detection|Ultrasonic Ran<br>ing|g-<br>real-world data|
||Sun et al.[341]|2021|Anti-Spoofing|Detection|mmWave Radar|<br>real-world data|
||Nallabolu et al.[279]|2021|Anti-Spoofing|Detection|mmWave Radar|<br>real-world data|
||Falco et al.[82]|2018|Anti-Spoofing|Detection|GNSS|Simulation data|
||Crowd-GPS-Sec[148]|2018|Anti-Spoofing|Detection|GNSS|Real-world data, Simula-<br>tion data|
||DeepSIM[441]|2020|Anti-Spoofing|Detection|GNSS|SatUAV(custom)|
||DeepPOSE[157]|2022|Anti-Spoofing|Detection|GNSS|BDD-100K, Custom dataset|
||Iqbal et al.[143]|2024|Anti-Spoofing|Detection|GNSS|TEXBAT|
||PADS[233]|2025|Anti-Spoofing|Detection|GNSS|Jammertest|
||Jin et al.[162]|2025|Anti-Spoofing|Detection|GNSS|Real-world data|
||SDI[351]|2020|Anti-Spoofing|Detection|IMU|Custom<br>dataset,<br>Real-<br>world data|
||Liu et al.[232]|2022|Anti-Spoofing|Detection|IMU|Custom<br>dataset,<br>Real-<br>world data|
||CPD-MhIMU[310]|2024|Anti-Spoofing|Detection|IMU|Custom<br>dataset,<br>Real-<br>world data|
||SAS[296]|2010|Anti-Spoofing|Authentication|GNSS|Simulation data|
||NMA[91]|2016|Anti-Spoofing|Authentication|GNSS|Real-world data, Simula-<br>tion data|
|Sensor<br>|Chimera[9]|2017|Anti-Spoofing|Authentication|GNSS|Real-world data, Simula-<br>tion data|
|Defense|Wang et al.[377]|2017|Anti-Spoofing|Mitigation|GNSS|Simulation data, TEXBAT|
||Eldosouky et al.[80]|2019|Anti-Spoofing|Mitigation|GNSS|Simulation data|
||Zhou et al.[520]|2023|Anti-Spoofing|Mitigation|GNSS|TEXBAT|
||Hong et al.[127]|2022|Anti-Spoofing|Mitigation|IMU|Simulation data|
||UNROCKER[149]|2023|Anti-Spoofing|Mitigation|IMU|Real-world data, Simula-<br>tion data|
||VIMU[403]|2024|Anti-Spoofing|Mitigation|IMU|Real-world data, Simula-<br>tion data|
||Zhang et al.[479]|2020|Anti-Spoofing|Mitigation|mmWave Radar|<br>real-world data|
||Chen et al. [41]|2025|Anti-Spoofing|Mitigation|Camera/ADAS|openpilot, CARLA|
||Swinney et al.[343]|2021|Anti-Jamming|Detection|GNSS|<br>Custom dataset|
||<br>Spanghero et al.[326|]<br>2025|Anti-Jamming|Detection|GNSS|Jammertest,<br>Real-world<br>data|
||Wang et al.[374]|2021|Anti-Jamming|Mitigation|GNSS|Simulation data|
||MFMC[146]|2022|Anti-Jamming|Mitigation|GNSS|Custom dataset|



19 

periods, and SecureTrack [322] incorporates EMI monitoring. For mmWave radar, Sun et al. [341] proposed challenge-response mechanisms, and Nallabolu and Li [279] designed hybrid-slope chirps. 

Authentication cryptographically verifies the authenticity and integrity of sensor signals to ensure they originate from legitimate sources. For GNSS, SAS [296] introduces encrypted authentication sequences to bind signals to their true source. NMA [91] demonstrates navigation message authentication for Galileo based on the TESLA protocol. Chimera [9] proposes time-binding tags that link signal transmission to precise time slots, preventing replay. 

Mitigation actively counteracts or reduces attack effects. For GNSS, Wang et al. [377] introduced MLE-based localization and cancellation, Eldosouky et al. [80] used cross-UAV localization, and Zhou et al. [520] proposed VTL-based correction pipelines. For IMU, Hong et al.’s work [127] combines LSTM prediction with CUSUM monitoring, UNROCKER [149] applies denoising autoencoders, and VIMU [403] integrates physical modeling with anomaly detection. For mmWave radar, Zhang et al. [479] introduced VANET-based coordination. For camera-based ADAS, Chen et al. [41] evaluated automated and human-driver safety interventions in open-source ADAS against adversarial patch attacks, analyzing intervention conflicts and their resolution to enhance system resilience. 

**Anti-Jamming Defenses** . Anti-jamming defenses enhance receiver resilience against intentional or unintentional interference through two strategies: Detection, which identifies jamming signals or interference patterns, and Mitigation, which suppresses or filters interference to restore signal integrity. 

For detection of jamming in GNSS, Swinney and Woods [343] fused frequency- and time-domain representations using VGG16 with transfer learning to detect jamming. Spanghero et al. [326] leveraged VTOL UAVs to localize jammers by analyzing spatial signal degradation patterns. 

For mitigation of jamming in GNSS, Wang et al. [374] demonstrated that reservoir computing and LSTM networks can reconstruct GPS signals corrupted by jamming. MFMC [146] develops multi-frequency, multi-constellation receivers to exploit signal diversity and reduce vulnerability. 

## **2.5 Cross-Modal Perception** 

Modern embodied systems increasingly rely on multi-sensor fusion (combining cameras, LiDAR, and radar) to achieve robust perception. Cross-modal perception introduces unique vulnerabilities absent from singlemodality systems: attackers can exploit inconsistencies between modalities, corrupt fusion mechanisms, or target the weakest channel to compromise the entire perception pipeline. These attacks are particularly dangerous because they can bypass defenses designed for individual modalities. This subsection reviews vulnerabilities and defenses in multi-modal perception models, organized into two parts: **Adversarial Attacks** (Section 2.5.1) target sensor fusion pipelines through cross-channel perturbations and temporal misalignment; and **Adversarial Defenses** (Section 2.5.2) protect fusion systems through certified robustness, adversarial training, and modality-specific sanitization. 

### **2.5.1 Adversarial Attacks** 

Multi-sensor fusion combines modalities to improve perception accuracy and robustness, but the fusion process itself introduces attack surfaces at the feature alignment, projection, and decision stages. 

**Digital Attacks** . Cao et al. [33] showed that adversarial perturbations can deceive multi-sensor fusion (camera + LiDAR) perception in autonomous driving by exploiting the cross-modal alignment between the two channels. DejaVu [318] exploits synchronization dependencies between sensors: a single-frame LiDAR delay causes 88.5% mAP degradation in 3D detection, while three-frame camera delays reduce MOT performance by 73% MOTA, revealing that temporal misalignment is a critical but underprotected attack surface. UMAB [209] crafts untargeted adversarial perturbations that break image-text modality alignment in large vision-language models. 

20 

**Table 10** A summary of **adversarial** attacks and defenses for **cross-modal perception** . 

|**Attack/Defe**|**nse**<br>**Method**|**Year**|**Category**|**Subcategory**|**Target Model**|**Dataset**|
|---|---|---|---|---|---|---|
||DejaVu[318]|2025|Digital Attack|Temporal Misalign<br>ment|-<br>Fusion 3D Dete<br>tor|c-<br>nuScenes|
||Cao et al.[33]|2021|Physical Attack|Adversarial Object|<br>Fusion 3D Dete<br>tor|c-<br>KITTI, nuScenes|
|Adil|Hallyburton<br>al.[117]|et<br>2022|Physical Attack|LiDAR Spoofing|Fusion 3D Dete<br>tor|c-<br>KITTI, nuScenes|
|versara<br>Attack|Li et al.[528]|2024|Physical Attack|Adversarial Object|<br>Fusion 3D Dete<br>tor|c-<br>nuScenes|
||Iranmanesh et al.[1|44]<br>2026|Physical Attack|Typographic|VLM|HomeRobot (Habitat)|
||Wang et al.[388]|2022|Robust Training|Adversarial Train<br>ing|-<br>Fusion 3D Dete<br>tor|c-<br>KITTI|
||MMCert[400]|2024|Robust Inference|Certified Defense|Multi-Modal<br>Model|Kinetics-400, Food-101|
|Adversarial<br>Defense|El-Fatyany [79]|2026|Robust Inference|Input Moderation|Fusion 3D Dete<br>tor|c-<br>nuScenes, KITTI|
||BlueSuffix[505]|2025|Robust Inference|Input Moderation|Vision-Languag<br>Model|e<br>MM-SafetyBench,<br>RedTeam-2K|



**Physical Attacks** . Physical attacks on cross-modal perception exploit the geometric correspondence between 2D images and 3D point clouds. Extending the digital fusion attack introduced above, Cao et al. [33] presented the first physical-world attack that simultaneously fools both camera and LiDAR channels using 3D-printed adversarial objects, demonstrating that physically realizable perturbations can evade all tested fusion-based detectors. Hallyburton et al. [117] proposed the frustum attack that compromises all eight widely-used perception algorithms (both LiDAR-only and camera-LiDAR fusion) through black-box LiDAR spoofing, while remaining stealthy to existing defenses. Li et al. [528] conducted the first comprehensive study attacking all three sensing modalities simultaneously (camera, LiDAR, and radar) using a single adversarial object that exploits cross-modal geometric constraints. Iranmanesh and Liu [144] extend typographic attacks to robot manipulation: printed scene text overrides CLIP-based VLM perception and propagates through HomeRobot’s sense-plan-act pipeline. 

### **2.5.2 Adversarial Defenses** 

Defenses for cross-modal perception systems exploit redundancy between modalities and enforce consistency constraints to detect or mitigate multi-channel attacks. 

**Robust Training** . Adversarial training for fusion models must account for cross-channel externalities. Wang et al. [388] discovered that single-channel adversarial training can reduce robustness to attacks on other channels (a cross-channel externality) and propose multi-channel adversarial training as a countermeasure. 

**Robust Inference** . Wang et al. [400] proposed MMCert, the first certified defense against adversarial attacks on multi-modal models, deriving provable robustness bounds through randomized smoothing across modalities. El-Fatyany [79] applied modality-specific input sanitization before sensor fusion, preventing adversarial patches on one modality from corrupting the joint representation. BlueSuffix [505] pairs visual and textual purifiers with a reinforcement-trained suffix generator to defend vision-language models against jailbreak attacks while preserving cross-modal alignment. 

# **3 Cognition** 

Cognition forms the second layer, encompassing perception while adding semantic interpretation and logical inference, expanding the agent’s capability from sensing to understanding. This expansion introduces 

21 

**Table 11** A summary of **cognitive attacks and defenses** for **embodied cognition** . 

|**Attack/Def**|**ense**<br>**Method**|**Year**|**Catego**|**ry**<br>**Subcategory**|**Target Model**|**Dataset/Benchmark**|
|---|---|---|---|---|---|---|
||CHAI [29]|2025|Instruct|ion Attack<br>Jailbreak Attacks|Embodied LLM|Simulation, Real World|
||BadNAVer [254]|2025|Instruct|ion Attack<br>Jailbreak Attacks|Navigation<br>Agent|Matterport3D|
||Seeing-No-Evil [196|]<br>2026|Instruct|ion Attack<br>Jailbreak Attacks|VLM|Custom|
||SDoS [329]|2026|Instruct|ion Attack<br>Jailbreak Attacks|Embodied LLM|Custom|
||Chen et al. [52]|2024|World <br>tack|Model At-<br>Hallucination|VLM|Custom|
||Tao et al. [37]|2025|World <br>tack|Model At-<br>Hallucination|VLM|Custom|
||HRSSM [336]|2024|World <br>tack|Model At-<br>Rule Violation|World Model|Custom|
||Wen et al. [364]|2025|World <br>tack|Model At-<br>Rule Violation|World Model|Custom|
|Cognitive<br>Attack|TRAP [78]|2026|World <br>tack|Model At-<br>Rule Violation|World Model|Custom|
||PhysCond-<br>WMA [113]|2026|World <br>tack|Model At-<br>Rule Violation|Diffusion WM|Custom|
||CtrlAttack [437]|2026|World <br>tack|Model At-<br>Rule Violation|World Model|Custom|
||H-CoT [180]|2025|Reason|ing Attack<br>CoT Hĳacking|Reasoning Mode|l<br>Custom|
||Altered<br>Thoughts [362]|2026|Reason|ing Attack<br>CoT Hĳacking|VLA|Custom|
||J-DAPT [268]|2025|Instruct|ion Defense<br>Jailbreak Defenses|<br>Embodied LLM|nuScenes,<br>Maritime,<br>Quadruped|
||Hafez et al. [115]|2025|Instruct|ion Defense<br>Jailbreak Defenses|<br>Embodied LLM|Gazebo, Real World|
||Ravichandran<br><br>al. [304]|et<br>2026|Instruct|ion Defense<br>Jailbreak Defenses|<br>LLM-Enabled<br>Robot|Custom|
||MASH-VLM [13]|2025|World <br>fense|Model De-<br>Hallucination|World Model|Custom|
||SafeDreamer [138]|2024|World <br>fense|Model De-<br>Rule Violation|World Model|Safety Gymnasium|
||Drive-WM [405]|2024|World <br>fense|Model De-<br>Rule Violation|World Model|nuScenes|
|Cognitive|VL-SAFE [300]|2025|World <br>fense|Model De-<br>Rule Violation|World Model|AD Simulation|
|Defense|Surprise<br>Recog<br>tion [530]|ni-<br>2025|World <br>fense|Model De-<br>Rule Violation|World Model|Custom|
||SafeDream [443]|2026|World <br>fense|Model De-<br>Rule Violation|LLM|Custom|
||HomeGuard [248]|2026|World|Model De-<br>Contextual<br>Ris|k<br>VLM|Custom|
||||fense|Mitigation|||



new attack surfaces beyond perceptual corruption: adversaries can now manipulate how agents interpret instructions, exploit world model hallucinations, and hĳack reasoning chains. With LLMs and VLMs increasingly serving as the “brain” of embodied systems, the cognitive layer becomes both the engine of intelligent behavior and a high-value target for adversarial manipulation. **Instruction Understanding** (Section 3.1) addresses jailbreak attacks that manipulate natural language instructions to bypass safety constraints and induce harmful intent understanding, along with corresponding defenses and benchmarks; **World Model** (Section 3.2) examines hallucination in scene understanding and rule violations in predictive models; and **Reasoning** (Section 3.3) covers chain-of-thought hĳacking attacks that corrupt reasoning. 

22 

## **3.1 Instruction Understanding** 

Embodied agents rely on natural language instructions to bridge human intent and physical action. Unlike text-only chatbots, where misinterpretation produces merely incorrect text, failures in embodied instruction understanding can trigger unsafe physical behaviors: collisions, property damage, or human injury. This subsection surveys jailbreak attacks that bypass safety guardrails to induce harmful intent understanding, corresponding defenses, and benchmarks for evaluating instruction safety. As embodied agents extend beyond text and vision to direct auditory input, recent surveys on Large Audio Language Models [251] indicate that LALMs will inherit and amplify these same instruction-attack surfaces, motivating proactive coverage of potential audio-borne jailbreak threats. 

**Jailbreak Attacks** . Jailbreak attacks manipulate language inputs to circumvent safety constraints, causing embodied agents to execute harmful physical actions that would normally be refused. CHAI [29] optimizes adversarial commands against the LVLM command layer of physical agents in the white-box setting. Black-box attacks at the sentence level craft semantically meaningful prompts that exploit weaknesses in safety filters. BadNAVer [254] demonstrates that jailbreaks in embodied navigation directly trigger unsafe physical actions. Seeing No Evil [196] shows that attention-guided visual perturbations can blind VLMs to safety instructions even when the safety prompt remains literally present. Steinberg and Gal [329] introduce semantic denial-ofservice: short, safety-plausible audio injections weaponize an Embodied LLM’s own safety reasoning to stall task execution. 

**Jailbreak Defenses** . Defenses against jailbreaks aim to detect or block adversarial instructions before they are translated into physical actions. J-DAPT [268] introduces multimodal domain adaptation for robotic jailbreak detection, using vision-language alignment to identify adversarial instructions before they reach the control pipeline. Hafez et al. [115] integrated reachability analysis with Embodied LLMs, providing formal safety guarantees by rejecting instructions whose predicted outcomes violate verified safety envelopes. Ravichandran et al. [304] propose a runtime safety guardrail for Embodied LLMs that addresses both LLM contextual vulnerabilities and downstream physical risks before execution. 

**Benchmarks** . IndustryEQA [207] extends embodied QA to safety-critical industrial environments with hazard recognition and compliance verification. SQA3D [259] introduces situated question answering in 3D scenes requiring spatial and commonsense reasoning. MMRO [197] benchmarks multimodal LLMs as cognitive engines for in-home robotics, revealing safety as a persistent weakness. MetaVQA [395] finetunes VLMs with embodied scene data to improve spatial reasoning in safety-critical driving simulations. AGENTSAFE [458] evaluates embodied agent vulnerability to jailbreaks across adversarial scenarios with hazardous tasks. EmbodiedBench [449] provides an evaluation framework with explicit safety metrics. 

## **3.2 World Model** 

World models enable embodied agents to predict future states, reason about physical dynamics, and evaluate action consequences before execution. When these internal representations diverge from physical reality (through hallucination, sim-to-real gaps, or prediction failures), agents make decisions based on false beliefs about their environment, with potentially catastrophic physical consequences. This subsection surveys threats to world model safety organized by two failure modes: **Hallucination in Scene Understanding** addresses VLM and world model hallucination that generates nonexistent objects, spatial relations, or actions; and **Rule Violation** covers predictive model failures and emergent misalignment that cause agents to violate physical laws, domain-specific rules, or safety constraints. 

**Hallucination in Scene Understanding** . VLM hallucination (generating descriptions of objects, spatial relations, or actions that do not exist in the physical scene) poses acute risks when these models serve as the perceptual backbone of embodied agents. Chen et al. [52] showed that multi-object hallucination in VLMs remains pervasive in embodied scene understanding, and Tao et al. [37] demonstrated that hallucination is especially severe in visual-text tasks for embodied agents. MASH-VLM [13] disentangles spatial and temporal tokens via DST-attention to reduce action-scene misattribution in world models. Beyond VLM 

23 

hallucination, world models used for internal simulation exhibit distinct pathologies. Baraldi et al. [18] identified scene-generation pathology criteria spanning temporal consistency, physical conformity, and condition consistency, confirming a systematic safety gap in current world model predictions. ContrAR [430] benchmarks VLM hallucination in AR with contradictory-overlay videos, exposing an inability to resolve observed-versus-asserted reality. 

**Rule Violation** . Beyond hallucination, world models can systematically violate physical laws, domainspecific rules, and safety constraints: failures that directly translate into unsafe embodied behavior. Predictive model failures occur when learned dynamics models compound errors over long horizons, producing increasingly dangerous predictions. Li et al. [206] surveyed world model architectures across RSSM, Transformer, diffusion, and other paradigms, identifying error accumulation, distribution shift, and physical consistency as critical safety challenges; Parmar [292] maps the safety, security, and cognitive risks of world models onto MITRE ATLAS and OWASP categories. TRAP [78] shows that world-model planners are vulnerable to a tail-aware ranking attack: small perturbations to the value-ranking tail of imagined trajectories steer the planner toward unsafe actions while leaving nominal accuracy untouched. PhysCond-WMA [113] perturbs the physical conditioning signals of diffusion world models in a two-stage guidance scheme, degrading downstream planner performance. CtrlAttack [437] extends this to image-to-video diffusion world models with a unified attack on action-conditioned state transitions, breaking the controllability that downstream policies rely on. HRSSM [336] learns latent dynamic robust representations to improve world model resilience to distribution shift. Tseng et al. [364] found that compounding errors in video prediction rollouts limit long-horizon reliability. Safety-aware world models explicitly incorporate constraints into the prediction-planning loop: SafeDreamer [138] integrates Lagrangian-based safety constraints into the Dreamer framework, VL-SAFE [300] supervises world models using VLM-derived safety scores for autonomous driving, and Drive-WM [405] uses multi-view diffusion for safer trajectory selection, though training planners on WM-generated data creates a cascading risk where pathologies propagate to downstream policies. Surprise Recognition [530] leverages the world model’s own intrinsic surprise signal to detect out-of-distribution distractors before they translate into unsafe actions, providing a model-internal anomaly channel that complements explicit safety constraints. SafeDream [443] ports the world-model defense idiom to LLM jailbreaks: a safety world model tracks cumulative safety-alignment erosion across multi-turn conversation, enabling proactive detection before harmful content is generated. 

**Contextual Risk Mitigation** . Beyond defending against in-model hallucination and rule violation, a complementary defense thread targets _contextual_ safety risk, where benign instructions become hazardous due to subtle environmental states that rule-based or prompt-engineered safeguards miss. HomeGuard [248] pairs attention-anchored perception with semantic judgment for household risk detection, with visual anchors doubling as spatial constraints for downstream planners. HazardArena [59] provides a pairedscenario benchmark that isolates contextual semantic risk: safe/unsafe twins share objects, layout, and action requirements but differ only in the semantic context that renders an action unsafe. Sermanet et al. [316] release the ASIMOV benchmark and generate robot constitutions, framing semantic safety as a first-class evaluation target for VLM-controlled robots. 

## **3.3 Reasoning** 

Reasoning addresses vulnerabilities in the processes embodied agents use for multi-step problem solving. 

**Chain-of-Thought Hĳacking** . Chain-of-thought (CoT) reasoning enables transparent multi-step deliberation but exposes intermediate reasoning steps to adversarial manipulation. H-CoT [180] demonstrates that inserting adversarial steps into chain-of-thought traces can hĳack reasoning models toward harmful conclusions. Altered Thoughts [362] probes entity-substitution vulnerabilities in chain-of-thought VLA manipulation policies, where corrupted reasoning steps degrade task execution. 

24 

# **4 Planning** 

Planning forms the third layer, encompassing perception and cognition while adding the generation of action sequences, expanding the agent’s capability from understanding to decision-making. This expanded capability extends the attack surface from passive interpretation to active goal pursuit: adversaries can now corrupt task decomposition, hĳack trajectory optimization, and manipulate multi-agent coordination strategies. Modern embodied planners increasingly leverage LLMs for high-level task decomposition while relying on traditional methods for low-level motion generation, creating a heterogeneous attack surface spanning both learned and classical components. Because planning spans multiple abstraction levels (from symbolic task decomposition through trajectory optimization to multi-agent coordination), each level admits qualitatively distinct attack vectors. This section organizes planning into three subsections: **Task Planning** (Section 4.1) addresses vulnerabilities in LLM-based task decomposition, chain-of-thought reasoning, and goal specification (this includes jailbreak attacks that manipulate planners into generating harmful action sequences, as well as goal hĳacking and reward hacking); **Trajectory Planning** (Section 4.2) covers threats to trajectory prediction and path planning, including adversarial perturbation of collision avoidance systems; and **Multi-Agent Planning** (Section 4.3) discusses planning-time coordination challenges including distributed task allocation, consensus failures, subgoal manipulation, and goal conflicts among cooperative agents. Note that multi-agent planning focuses on the **planning phase** (who does what), while execution-time collaboration is covered in Section 5. 

## **4.1 Task Planning** 

Task planning translates high-level objectives into actionable subgoal sequences, increasingly through LLM-based decomposition, chain-of-thought reasoning, and tool use. These capabilities enable flexible, generalizable planning but also introduce novel attack surfaces: adversaries can manipulate task specifications to induce unsafe decompositions, hĳack reasoning chains to subvert intended goals, or exploit jailbreak vulnerabilities to elicit harmful plans. This subsection examines adversarial attacks on classical optimizationbased planners and modern LLM-based task decomposition, jailbreak attacks that manipulate planners into generating harmful action sequences, backdoor attacks that implant hidden triggers, jailbreak defenses that prevent malicious instruction injection, and emerging risks including unforced constraints violation. 

### **4.1.1 Adversarial Attacks** 

Adversarial attacks on task planners primarily target black-box threat models where attackers perturb inputs or environmental states without model access. Islam et al. [145] demonstrated that small visual perturbations can mislead CLIP-based vision–language navigation systems into attacker-defined paths, highlighting vulnerabilities in vision-grounded task planners. Vemprala and Kapoor [368] showed that adversarial state configurations can degrade eigenstructure in classical optimization-based planners, forcing failure or excessive computation. AFM [468] generates adversarial perturbations through a one-step flow-matching velocity field, transferring across vision-language-action and modular end-to-end driving stacks to induce hazardous maneuvers. 

### **4.1.2 Jailbreak Attacks** 

Jailbreak attacks manipulate LLM-based planners by crafting inputs that bypass safety guardrails to elicit harmful task decompositions. 

**White-box Attacks** . White-box attacks leverage gradient-based optimization to craft adversarial suffixes or token-level perturbations. EIRAD [231] adapts gradient-based suffix optimization, appending adversarial tokens to benign inputs so that untargeted variants divert the agent from the intended task while targeted variants steer outputs toward harmful goals. POEX [249] improves suffix quality through a mutator–selector– evaluator loop that balances jailbreak success with action executability, validating attacks on real robots and introducing Harmful-RLBench, a benign–harmful task suite for sim-to-real safety evaluation. 

25 

**Table 12** A summary of **attacks and defenses** for **embodied planning** . 

|**Attack/Defen**|**se**<br>**Method**|**Year**|**Category**|**Subcategory**|**Target Model**|**Environment**||
|---|---|---|---|---|---|---|---|
||Zhang et al. [482]|2022|White-box|Optim.-Based Attack|Trajectory Planner|Apolloscape,<br>nuScenes|NGSIM,|
||AdvDO [34]|2022|White-box|Optim.-Based Attack|Trajectory Planner|nuScenes||
||KING [120]|2022|White-box|Optim.-Based Attack|Trajectory Planner|CARLA||
||ADvLM [488]|2024|White-box|Optim.-Based Attack|Trajectory Planner|nuScenes, Driv|eLM|
||Adv-GAN [83]|2024|White-box|Model-Based Attack|Trajectory Planner|Apolloscape,<br>nuScenes|NGSIM,|
||Islam et al. [145]<br>|2024|Black-box<br>|Optim.-Based Attack<br>|Task Planner<br>|EnvLarge-10<br>||
||AdvSim [382]|2021|Black-box|Optim.-Based Attack|Trajectory Planner|UrbanScenario|s|
|Adversarial|STRIVE [306]|2022|Black-box|<br>Optim.-Based Attack|<br>Trajectory Planner|nuScenes||
|Attack|Zheng et al. [512]|2023|Black-box|Optim.-Based Attack|Trajectory Planner|nuScenes, Arg|overse|
||UTCIA [16]|2025|Black-box|Optim.-Based Attack|Trajectory Planner|Trajectory Data|sets|
||Avatar [228]|2025|Black-box|Optim.-Based Attack|Trajectory Planner|Waymax||
||LC [73]|2020|Black-box|Model-Based Attack|Trajectory Planner|CARLA||
||NADE [89]|2021|Black-box|Model-Based Attack|Trajectory Planner|CARLA||
||AdvDiffuser [428]|2024|Black-box|Model-Based Attack|Trajectory Planner|nuScenes||
||Szvoren et al. [344]|2025|Black-box|Physical Attack|Trajectory Planner|Gazebo, Unitre|e Go1|
||AFM [468]|2026|White-box|Optim.-Based Attack|E2E AD Model|CARLA, Bench|2Drive|
||EIRAD [231]|2024|White-box|Word-Level|Task Planner|AI2-THOR||
||POEX [249]|2024|White-box|Word-Level|Task Planner|CoppeliaSim,<br>Real world|RLBench,|
||RoboPAIR [308]|2024|Black-box|Sentence-Level|Task Planner|nuScenes, Real|world|
|Jailbreak<br>|BADROBOT [472]|2024|Black-box|Sentence-Level|Task Planner|RLBench, Real|world|
|Attack|Wen et al. [409]|2024|Black-box|Sentence-Level|Trajectory Planner|Touchdown, M|ap2seq|
||Zhang et al. [490]|2024|Black-box|Sentence-Level|<br>Trajectory Planner|<br>EyeSim VR||
||PINA [229]|2026|Black-box|Sentence-Level|Trajectory Planner|Indoor/Outdo<br>tion|or<br>Naviga-|
||CBA [222]|2024|Data Poisoning|Multi-Modal Triggers|Task Planner|ProgPrompt, V<br>Prog, Real|oxPoser, Vis-|
|Backdoor<br>|BALD [160]|2024|Training Manip<br>lation|u-<br>Multi-Modal Triggers|Task Planner|HighwayEnv,<br>nuScenes|CARLA,|
|Attack|Robo-Troj [276]|2025|Training Manip<br>lation|u-<br>Word-Level Triggers|Task Planner|VirtualHome,|AI2-THOR|
||Thumm et al. [352]|2023|Robust Training|<br>Safety Constraints|Trajectory Planner|OpenAI safety|gym|
||AR-ICRL [436]|2024|Robust Training|<br>Safety Constraints|Trajectory Planner|Blocked<br>Cheetah/Ant/|Half-<br>Walker|
|Adversarial<br>|Yurtsever et al. [466]|2019|Robust Inferenc|e<br>Output Moderation|Trajectory Planner|NuDrive||
|Defense|SMPC [27]|2021|Robust Inferenc|<br>e<br>Output Moderation|<br>Trajectory Planner|Matlab||
||CSP-GAN-<br>LSTM [271]|2023|Robust Inferenc|<br>e<br>Output Moderation|<br>Trajectory Planner|NGSIM, highD||
||SafeEmbodAI [489]|2024|Robust Inferenc|e<br>Safe Prompt|Trajectory Planner|EyeSim VR||
||NPE [409]|2024|Robust Inferenc|e<br>Safe Prompt|Trajectory Planner|Touchdown, M|ap2seq|
||SafePlan [288]|2025|Robust Inferenc|<br>e<br>Safe Prompt|<br>Task Planner|<br>AI2-THOR, Sy|<br>nthetic|
|ilbk|J-DAPT [268]|2025|Robust Inferenc|e<br>Jailbreak Detection|Trajectory Planner|nuScenes,|Maritime,|
|Jarea<br>||||||Quadruped||
|Defense|RoboSafe [386]|2025|Robust Inferenc|e<br>Runtime Safety|Task/Traj Planner|AI2-THOR, Me|taWorld|
||CEE [446]|2025|Robust Inferenc|e<br>Representation Eng.|Task Planner|EI Safety Bench|marks|
||Zhang et al. [491]|2025|Robust Inferenc|e<br>Runtime Safety|Trajectory Planner|EyeSim, Real w|orld|



26 

**Table 13** A summary of **emerging risks** for **embodied planning** . 

|**Risk**|**Method**|**Year**|**Category**|**Subcategory**|**Target Model**|**Environment**|
|---|---|---|---|---|---|---|
||Strobel<br>and<br><br>rer [330]|Fer-<br>2020|Multi-Agent|Byzantine Faults|Multi-Agent Planner|Physical Robots|
||Blumenkamp<br>al. [26]|et<br>2021|Multi-Agent|Byzantine Faults|Multi-Agent Planner|Coverage, Path Planning|
||He et al. [124]|2025|Multi-Agent|Byzantine Faults|Multi-Agent Planner|Multi-Agent Frameworks|
||Zhou et al. [516]|2026|Multi-Agent|Byzantine Faults|Multi-Agent Planner|GQA|
||Choudhury et al.|[66]<br>2022|Multi-Agent|Goal Conflicts|Multi-Agent Planner|Task Allocation|
||Bahrami and Jafa|rne-<br>2025|Multi-Agent|Goal Conflicts|Multi-Agent Planner|Relative Localization|
|Emerging<br>|jadsani [14]||||||
|Risks|Li et al. [193]|2020|Multi-Agent|Potential Defenses|Multi-Agent Planner|Multi-Robot Networks|
||Strobel et al. [331]|2023|Multi-Agent|Potential Defenses|Multi-Agent Planner|24 Physical Robots|
||Lee<br><br>Panagou [184]|and<br>2025|Multi-Agent|Potential Defenses|Multi-Agent Planner|Distributed Control|
||Gandhi et al. [99]|2025|Multi-Agent|Potential Defenses|Multi-Agent Planner|Physical Robots|



**Black-box Attacks** . Black-box attacks manipulate instructions without model access, operating through prompt engineering and semantic manipulation. RoboPAIR [308] automates jailbreak generation by extending PAIR with robot-specific prompts and a syntax checker that enforces API-compliant action formats. BADROBOT [472] identifies three embodiment-specific attack surfaces: contextual jailbreak, safety misalignment, and conceptual deception, showing that Embodied LLMs can be coerced into unsafe actions using in-the-wild prompts across both simulation and physical platforms. 

### **4.1.3 Backdoor Attacks** 

Backdoor attacks implant hidden triggers into task planners during pre-training or fine-tuning while preserving clean-task performance, enabling malicious behaviors to activate only when the trigger appears at deployment. CBA [222] poisons in-context demonstrations using combined textual and visual triggers to activate harmful behaviors at deployment. BALD [160] taxonomizes backdoor pathways in LLM-based planners, covering word-level triggers, scenario manipulation, and RAG-based knowledge injection. RoboTroj [276] demonstrates backdoor attacks via poisonous fine-tuning of soft-prompts to inject malicious plans when trigger words appear in task descriptions. 

### **4.1.4 Jailbreak Defenses** 

Jailbreak defenses for task planning focus on preventing malicious instruction injection and ensuring that LLM-based planners adhere to safety constraints during deployment. Current strategies employ safe prompting, jailbreak detection, runtime validation, and representation engineering techniques. 

SafeEmbodAI [489] integrates safe prompting, state management, and safety validation modules to verify and sanitize actions before execution, preventing unsafe navigation behaviors. NPE [409] employs structured templates such as Chain-of-Thought and Plan-and-Solve to improve planner robustness against text-based manipulations. J-DAPT [268] integrates textual and visual embeddings via attention-based fusion and adapts general jailbreak datasets to robotics-specific domains for multimodal detection. RoboSafe [386] combines backward reflective reasoning over recent trajectories with forward predictive reasoning from safety memory to generate executable predicate-based safety logic. Concept Enhancement Engineering (CEE) [446] steers internal representations toward safe concepts to defend against jailbreak attacks in embodied AI systems. SafePlan [288] interposes formal logic verification at multiple points in the CoT pipeline to filter unsafe robotic task plans. A unified framework for security and safety in Embodied LLMs [491] combines interpretable prompting, state-aware planning, and real-time validation to jointly address safety and prompt-injection security in mobile Embodied LLMs. 

27 

## **4.2 Trajectory Planning** 

Trajectory planning generates continuous trajectories that satisfy kinematic, dynamic, and safety constraints. Modern approaches combine learned trajectory prediction with classical path planning and collision avoidance, creating hybrid systems that inherit vulnerabilities from both paradigms. Attacks on trajectory planners can induce collisions, amplify prediction errors, or degrade trajectory quality through adversarial perturbations to perception inputs, prediction models, or planning algorithms. This subsection examines adversarial attacks on trajectory prediction and path planning, jailbreak attacks on LLM-based navigation planners, and adversarial defenses through robust training and inference. 

### **4.2.1 Adversarial Attacks** 

Adversarial attacks on trajectory planners exploit weaknesses in trajectory prediction and generation models, driving agents toward unsafe maneuvers or systematically amplifying prediction errors. These attacks fall into two main classes: white-box attacks, which use gradient-based methods to craft perturbations on trajectories or map context with full model access, and black-box attacks, which leverage query-based optimization or generative models to synthesize realistic adversarial scenarios without model access. 

**White-box Attacks** . White-box attacks leverage model gradients to craft precise adversarial perturbations on trajectories or context maps. Zhang et al. [482] perturbed nominal vehicle trajectories to maximize prediction error in trajectory forecasting models. AdvDO [34] uses a differentiable dynamics model to construct plausible adversarial trajectories that mislead downstream planners. KING [120] employs a differentiable kinematic model to efficiently search for critical but feasible scenes. Adv-GAN [83] employs an LSTM-based generator to produce adversarial trajectory perturbations and refines them using model predictive control under realism and safety constraints. ADvLM [488] addresses textual instruction variability and time-series visual scenarios in VLM-based autonomous driving through Semantic-Invariant Induction for diverse prompt libraries and Scenario-Associated Enhancement for frame-perspective optimization. 

**Black-box Attacks** . Black-box attacks operate without model access, relying on query-based optimization, surrogate models, or RL to generate failure-inducing scenarios. AdvSim [382] provides a general black-box adversarial scenario search framework for end-to-end planners. STRIVE [306] perturbs real-world scenes in the latent space of a VAE-based traffic motion model to generate challenging scenarios for stress-testing. Zheng et al. [512] introduced adversarial corruption of context maps required by trajectory predictors. UTCIA [16] generates universal black-box adversarial perturbations for trajectory representation learning. Avatar [228] uses RL to optimize adversarial trajectories without model access. LC [73] trains RL agents to act as adversaries, intentionally inducing collisions and exposing weaknesses in planners. AdvDiffuser [428] leverages diffusion guidance to synthesize realistic yet failure-inducing trajectories. NADE [89] generates naturalistic adversarial driving scenarios to stress-test end-to-end planners. 

Physical adversarial attacks on robot trajectory planners [420] characterize how environmental manipulation can cause planner failures in deployments. JackZebra [335] demonstrates long-horizon goal hĳacking through adversarial patches on an attacker vehicle, steering a victim AV to an attacker-chosen destination. 

### **4.2.2 Jailbreak Attacks** 

Jailbreak attacks targeting LLM-based navigation systems manipulate natural language instructions to bypass safety constraints and elicit unsafe navigation behaviors. Unlike task planning jailbreaks that corrupt high-level goal decomposition, navigation jailbreaks directly compromise low-level trajectory generation. 

Zhang et al. [490] modeled Obvious Malicious Injection (OMI) and Goal Hĳacking Injection (GHI) against LLM-integrated mobile robots. Wen et al. [409] demonstrated that insertion and swap attacks significantly degrade the performance of GPT-3, GPT-4, and LLaMA-based navigation planners on Touchdown and Map2Seq, with errors concentrated at intersections and other high-ambiguity locations. PINA [229] extends prompt injection to misguide physical navigation, leading to unsafe routes and mission failure. 

28 

### **4.2.3 Adversarial Defenses** 

Adversarial defenses for trajectory planning operate through robust training, which incorporates safety constraints during learning, and robust inference, which applies output moderation at deployment. 

**Robust Training** . Robust training integrates safety constraints into the learning process. Thumm et al. [352] proposed proactive replacement and projection methods that modify agent actions during RL training to reduce failsafe interventions, yielding policies with fewer safety violations. AR-ICRL [436] extends inverse RL to infer safety constraints from expert demonstrations that remain valid even under model misspecification. 

**Robust Inference** . Robust inference defends planners at deployment through output moderation. SMPC [27] uses stochastic model predictive control with backup trajectories computed via reachable sets, overwriting planned outputs when safety constraints are violated. Yurtsever et al. [466] identified hazardous behaviors at runtime, enabling planners to filter or down-weight high-risk maneuvers. CSP-GAN-LSTM [271] combines convolutional pooling with attention-based trajectory prediction to compute collision risk via time-to-collision metrics during inference. 

## **4.3 Multi-Agent Planning** 

Multi-agent planning extends single-agent task and trajectory planning to teams of embodied agents that must jointly decompose tasks, allocate subtasks, and synthesize coordinated plans. This distributed setting introduces unique attack surfaces: an adversary can compromise a single agent’s planner to inject malicious subtasks that cascade through the team, manipulate inter-agent communication to corrupt plan consensus, or exploit Byzantine faults to subvert collective decision-making. 

### **4.3.1 Byzantine Faults** 

Byzantine faults arise when agents exhibit arbitrary or malicious behavior during distributed planning, corrupting consensus formation and task allocation. Strobel and Ferrer [330] demonstrated that classical consensus algorithms break down under Byzantine attacks in swarm robotics. Blumenkamp and Prorok [26] showed that self-interested agents in multi-robot planning tasks learn manipulative communication strategies through a differentiable shared channel, suggesting that adversarial behavior may emerge naturally from competitive pressure. He et al. [124] introduced the Agent-in-the-Middle (AiTM) attack that intercepts and manipulates messages between LLM-based agents during cooperative planning. Zhou et al. [516] mount hierarchical attacks on multi-modal multi-agent reasoning, jointly biasing message content, interaction topology, and the cognitive pipeline to corrupt collective decisions. Schroeder de Witt [71] taxonomizes multi-agent security threats including cascading failures, monoculture collapse, and conformity bias that drives false consensus on unsafe plans. 

### **4.3.2 Goal Conflicts** 

Adversarial or self-interested agents exploit cooperative planning protocols to advance conflicting objectives. Choudhury et al. [66] formulated robust task allocation strategies that maintain plan quality under adversarial cost perturbation. KA et al. [165] identified security-relevant gaps in multi-robot task allocation including lack of authentication and absence of Byzantine robustness guarantees. Bahrami and Jafarnejadsani [14] examined how adversarial perception attacks propagate through multi-robot relative localization to corrupt downstream coordination and planning. Zhou and Tokekar [517] reviewed algorithmic trends for robust multi-robot coordination under adversarial agents, while Sookha and Benevenuto [328] provided a taxonomy of adversarial attacks on multi-agent reinforcement learning that can corrupt learned planning policies. 

### **4.3.3 Potential Defenses** 

Resilient algorithms ensure that cooperative planning converges correctly despite misbehaving agents. Li et al. [193] proposed a centerpoint-based aggregation rule that guarantees convergence to the true target state even when adversarial robots inject arbitrary state estimates. Strobel et al. [331] deployed smart contracts that 

29 

regulate a crypto-token economy among physical robots, causing Byzantine robots to exhaust their tokens and be neutralized. Lee and Panagou [184] designed a CBF-based distributed controller that guarantees resilient consensus and collision avoidance using only locally available information. Gandhi et al. [99] presented RoboRebound, extending Byzantine fault tolerance to physical multi-robot systems where adversarial agents can block paths or cause collisions. 

## **4.4 Benchmarks** 

Simulation platforms, scenario-generation tools, and benchmarks constitute the foundational infrastructure for developing and evaluating embodied planners. These components differ in fidelity, scalability, and safety focus, yet collectively enable systematic stress-testing of algorithms. Simulation environments provide arenas for agent interaction, scenario design frameworks construct complex and safety-critical situations, and benchmarks integrate both into standardized evaluation pipelines. Together, they enable systematic stress-testing of planning algorithms under adversarial, rare, and out-of-distribution conditions. 

**Simulation Platforms** . Simulation platforms for embodied planning vary in realism, efficiency, and task coverage. For autonomous driving, SUMMIT [31] provides high-fidelity 3D towns with diverse agents and configurable weather, while HIGH-ENV [188] offers a lightweight 2D setup for prototyping. CARLA [76] extends fidelity through configurable vehicles, pedestrians, and scenes, and MetaDrive [202] uses procedural generation to produce large distributions of driving layouts. NAVSIM [70] complements these with datasetreplay environments for cost-effective evaluation. In robotics, platforms emphasize physics accuracy and multi-task support. Gazebo [177] integrates ROS and multiple physics engines for navigation and multi-robot coordination. PyBullet [68] offers a Python API and built-in robot models adopted in RL. MuJoCo [356] provides high-precision contact dynamics for locomotion and manipulation. Habitat [297] scales visual navigation in realistic indoor environments, iGibson [191] supports physically grounded manipulation tasks, and NVIDIA Isaac Sim [287] delivers photorealistic rendering with GPU-accelerated physics. 

**Scenario Design Tools** . Scenario design tools build on simulators to specify safety-critical interactions in a repeatable way. CARLA Scenario Runner [76] provides a Python API and OpenSCENARIO support for multi-agent coordination. SCENIC [94] introduces a probabilistic programming language for expressing spatial and temporal relationships, enabling concise specification of rare and complex events. SafeBench [432] integrates eight categories of critical driving scenarios and multiple generation algorithms for systematic safety evaluation. SUMO NETEDIT [241] offers graphical editing of road networks for traffic-scale simulations, and CommonRoad [397] supplies XML-based scenario definitions and a Python API for standardized motion-planning research. Together, these tools span language-based specification, graphical editing, and benchmark-oriented safety testing, enabling comprehensive evaluation of embodied planners. 

Benchmarks build on simulation and scenario design to create standardized, repeatable pipelines for evaluating embodied planners under adversarial, rare, and out-of-distribution conditions. Bench2Drive [155] offers a closed-loop driving suite with 220 routes spanning diverse weather, traffic, and map settings, isolating core planning skills such as lane keeping, merging, overtaking, and emergency handling. M3Bench [502] targets mobile manipulation with 30,000 pick-and-place tasks across 119 household scenes, providing expert demonstrations and tests of generalization to novel objects and layouts. THOR-EAE [398] assesses both action selection and natural language explanation with 840,000 samples in AI2-THOR. EAI [200] standardizes evaluation for LLM-driven agents, unifying protocols across navigation and interaction, decomposing execution into subgoals, and benchmarking eighteen state-of-the-art models with detailed error analysis. 

Safety-focused benchmarks have proliferated to address planning-specific hazards. AgentSafe [458] measures multimodal reasoning in long-horizon navigation with adversarial simulation scenarios and risk-aware task suites inspired by Asimov’s Three Laws. HASARD [359] evaluates interactive household manipulation with affordance-level annotations. Safe-BeAl [141] focuses on hazardous and adversarial settings to assess an agent’s risk awareness and robustness. SafeAgentBench [457] evaluates embodied agent safety through executable tasks spanning explicit and implicit hazards. AGENTSAFE [267] benchmarks safety of embodied agents on hazardous instructions with multi-stage evaluation across perception, planning, and execution. 

30 

SafeMindBench [45] benchmarks safety risks in embodied LLM agents. DESPITE [486] contributes a PDDL benchmark that separates planning competence from safety competence, finding LLM planners produce dangerous plans even when nominal task accuracy is high. For domain-specific safety, Nakao and Takemoto [278] evaluate LLMs on a medical-ethics benchmark for robotic health-attendant control. RoboJailBench [456] provides a jailbreak attack/defense benchmark for embodied VLMs, pairing an ISOderived security taxonomy with adversarial–benign intent contrast. 

# **5 Action and Interaction** 

Action forms the fourth layer, encompassing perception, cognition, and planning while adding physical execution, expanding the agent’s capability from decision-making to real-world interaction. This expansion carries the highest stakes and broadens the attack surface to the physical domain: adversaries can now corrupt control policies to cause collisions, exploit human-agent interaction to endanger people, and poison multi-agent coordination to induce swarm-level failures. In end-to-end models like VLA, this layer represents the full system from visual input to action output. This section organizes action and interaction into three subsections: **Robot Control** (Section 5.1) addresses robustness of low-level control policies, including RL-based controllers, diffusion policies, and VLA models; **Human-Agent Interaction** (Section 5.2) examines safety in human-agent physical interaction, including handover safety and trust manipulation; and **Multi-Agent Collaboration** (Section 5.3) covers execution-time coordination among multiple agents, focusing on infection attacks that propagate adversarial behaviors across agent populations and multi-agent collusion where autonomous agents deliberately coordinate malicious activities. 

## **5.1 Robot Control** 

After perceiving the environment, understanding the situation, and planning a trajectory, an embodied agent must reliably execute actions in the physical world. Safe control is therefore essential to trustworthy embodied AI, ensuring robustness under uncertainty and resilience to adversarial influence. Recent surveys [272] chart the rapid convergence of deep reinforcement learning with foundation models, motivating the safety focus on increasingly capable yet less interpretable control policies. Existing work on safe control falls into four categories: **Adversarial Attacks** , **Adversarial Defenses** , **Backdoor Attacks** , and **Backdoor Defenses** . Adversarial attacks and defenses address inference-time perturbations to states, actions, or environments, while backdoor attacks and defenses focus on hidden triggers that remain dormant during normal operation but activate harmful behaviors when invoked. 

### **5.1.1 Adversarial Attacks** 

Adversarial attacks on embodied agents exploit weaknesses in RL control policies to induce unsafe or unintended behaviors. These attacks perturb inputs such as states, actions, or observations and fall into two main categories: white-box attacks, which compute or train perturbations using full access to model parameters, and black-box attacks, which rely solely on interactive queries. Both classes target multiple vulnerability surfaces (state [S], action [A], environment [E], vision [V], and language [L]) and are evaluated across diverse platforms such as MuJoCo, Gym, RoboMimic, and LIBERO (Table 14). 

**White-box Attacks.** White-box attacks compute perturbations using gradients from the victim model. For MLP-based agents, CPA and AA [334] use trajectory sampling and adversarial policies to produce stealthy attacks, while RS and MAD [473] optimize perturbations by smoothing value functions or maximizing action divergence. For continuous control, Weng et al. [412] studied state and action perturbations using learned dynamics, and MAS and LAS [185] impose spatiotemporal constraints to preserve action plausibility. 

Modern policy architectures introduce new attack surfaces. DP-Attacker [54] perturbs camera observations in Diffusion Policies (DP) to exploit autoregressive dependencies, a vulnerability further analyzed by Kalra et al. [168] for Decision Transformer (DT) agents. For VLAs, UADA, UPA, and TMA [392] attack visual channels in BridgeData, LIBERO, and UR10e robots, inducing deviations through untargeted and targeted perturbations. 

31 

**Table 14** A summary of **adversarial attacks** for **robot control** . For clarity, we append suffixes to the target model (MLP, DP, DT, VLA), where **S** , **A** , **E** , **V** , and **L** denote attack surfaces on _State_ , _Action_ , _Environment_ , _Vision_ , and _Language_ . 

|**Attack**|**Method**|**Year**|**Category**|**Subcategory**|**Target Model**|**Environment**|
|---|---|---|---|---|---|---|
||CPA/AA[334]|2020|White-Box|Optim.-Based Attac|k<br>MLP-S|Atari, MuJoCo|
||RS/MAD[473]|2020|White-Box|Optim.-Based Attac|k<br>MLP-S|Atari, MuJoCo|
||Weng et al.[412]|2020|White-Box|Optim.-Based Attac|k<br>MLP-S|MuJoCo|
||MAS/LAS[185]|2020|White-Box|Optim.-Based Attac|k<br>MLP-A|Atari, Gym|
||DP-Attacker[54]|2024|White-Box|Optim.-Based Attac|k<br>DP-S|Robosuite|
||Kalra et al.[168]|2025|White-Box|Optim.-Based Attac|k<br>DP-S/DT-S|RoboMimic|
||UADA/UPA/TMA[39|2]<br>2025|White-Box|Optim.-Based Attac|k<br>VLA-V|BridgeData,<br>LIBERO,<br>UR10e|
||PVEP[60]|2024|White-Box|Optim.-Based Attac|k<br>VLA-V|VIMA, SIMPLER|
||UPA-RFAS[246]|2025|White-Box|Optim.-Based Attac|k<br>VLA-V|BridgeData, LIBERO|
||FreezeVLA[399]|2025|White-Box|Optim.-Based Attac|k<br>VLA-V|LIBERO|
||EDPA[433]|2025|White-Box|Optim.-Based Attac|k<br>VLA-V|LIBERO|
||Tex3D [42]|2026|White-Box|Optim.-Based Attac|k<br>VLA-V|LIBERO|
||Zhao et al.[504]|2024|White-Box|Optim.-Based Attac|k<br>VLA-L|VIMA|
||Jones et al.[164]|2025|White-Box|Optim.-Based Attac|k<br>VLA-L|LIBERO,<br>HYDRA,<br>SIM-<br>PLER|
|Adversarial|ADVLA[481]|2025|White-Box|Optim.-Based Attac|k<br>VLA-L|LIBERO|
|Attack|VLA-Fool[445]|2025|White-Box|Optim.-Based Attac|k<br>VLA-V/L|LIBERO|
||UniAda [477]|2024|White-Box|Optim.-Based Attac|k<br>VLM-V|nuScenes, CARLA|
||PA-AD[337]|2022|White-Box|Adversarial Policy|MLP-S|Atari, MuJoCo|
||ANNIE-Attack[140]|2025|White-Box|Adversarial Policy|VLA-V|ANNIEBench|
||SA-RL[474]|2021|Black-Box|Adversarial Policy|MLP-S|MuJoCo|
||RAT[15]|2025|Black-Box|Adversarial Policy|MLP-S|MuJoCo, Meta-World|
||AP-MARL[104]|2020|Black-Box|Adversarial Policy|MA-MLP-S|MuJoCo|
||IMAP[510]|2024|Black-Box|Adversarial Policy|(MA-)MLP-S|MuJoCo|
||SUB-PLAY[258]|2024|Black-Box|Adversarial Policy|MA-MLP-S|MPE|
||LIBERO-Plus [87]|2025|Black-Box|Adversarial Policy|VLA-V|LIBERO-Plus|
||DAERT [360]|2026|Black-Box|Adversarial Policy|VLA-L|CALVIN, RLBench|
||ERT[169]|2024|Black-Box|Adversarial Policy|VLA-L/DP-L|CALVIN, RLBench|
||RedVLA [498]|2026|Black-Box|Adversarial Policy|VLA-V/L|Real Robot|
||ADVEDM [401]|2025|Black-Box|Optim.-Based Attac|k<br>VLM-V|VIMA, nuScenes|
||JailWAM [226]|2026|Black-Box|Optim.-Based Attac|k<br>WAM-L|LIBERO|



32 

Building on these visual-channel attacks, UPA-RFAS [246] learns a physical patch in a shared feature space across models to achieve transferable adversarial manipulation. FreezeVLA [399] generates cross-prompt adversarial images to induce action-freezing behaviors across diverse user instructions. Similarly, EDPA [433] generates adversarial patches to distort visual understanding in VLAs, leading to failed action execution. Moreover, PVEP [60] expands these attacks with blurs, typography prompts, and adversarial patches in VIMA and SIMPLER. Tex3D [42] optimizes adversarial 3D textures via foreground-background decoupled differentiable rendering, turning physical objects into attack surfaces against VLAs. Language channels are similarly vulnerable: Zhao et al. [504] and Jones et al. [164] adapted GCG-style suffix optimization to manipulate decision outputs of VLAs. ADVLA [481] projects the visual features of adversarial perturbations into the textual feature space, thereby disrupting action prediction. To further characterize cross-modal vulnerabilities, VLA-Fool [445] unifies textual, visual, and cross-modal attacks and introduces an automatically crafted prompting framework. JailWAM [226] jailbreaks world-action models via visual-trajectory mapping and dual-path physical-simulator verification, exploiting the language interface as policies subsume planning. 

Adversarial agents can also be trained to attack sequentially. PA-AD [337] extends adversarial policies to continuous control, and ANNIE-Attack [140] evaluates VLA robustness within ANNIEBench. 

**Black-box Attacks.** Black-box attacks operate without access to model parameters, relying instead on adversarial policies or interaction-driven perturbations. SA-RL [474] optimizes state perturbations in MuJoCo through sequential interaction, while RAT [15] induces targeted failures across MuJoCo and Meta-World. 

Multi-agent settings introduce additional vulnerabilities. AP-MARL [104] trains red-team agents to manipulate cooperative or competitive partners. IMAP [510] learns intrinsically motivated adversaries that seek out weakness-exposing states, and SUB-PLAY [258] exploits partial observability to create deceptive multi-agent interactions. ERT [169] further extends black-box threats to VLM-driven robots via instruction-grounded redteaming, and DAERT [360] extends the same lineage with diversity-aware paraphrasing that uncovers linguistic fragility unreachable by template-bound prompts. RedVLA [498] closes the loop with physical red-teaming on real VLA-controlled robots, exposing failure modes that simulation-only protocols miss. LIBERO-Plus [87] introduces a comprehensive benchmark for safety evaluation of VLAs, investigating performance drops under diverse conditions ranging from lighting changes to camera pose variations. LIBERO-X [378] proposes a hierarchical evaluation protocol from spatial perturbation to semantic reformulation, finding VLAs strong on standard benchmarks collapse under minor distributional shifts. ADVEDM [401] proposes a fine-grained black-box adversarial attack framework against VLM-based policies that semantically edits only a few key objects while preserving the remaining regions, reducing conflicts with task context and inducing valid but incorrect decisions. For end-to-end autonomous driving, UniAda [477] unifies multi-objective universal adversarial attacks across perception, prediction, and planning modules. 

### **5.1.2 Adversarial Defenses** 

Defenses against adversarial attacks in embodied interaction fall into two categories: robust training, which incorporates adversaries or regularization during learning, and robust inference, which protects policies at deployment through input filtering or ensemble strategies. These methods address a wide range of attack surfaces and have been evaluated across MuJoCo, SMAC, and real robotic systems (Table 15). 

**Robust Training.** Robust training defenses embed adversarial resilience directly into the learning process. At the environment level, methods such as EPOpt [303] and RARL [295] train policies against ensembles of perturbed environments or destabilizing opponents, while ARPL [265] generates plausible adversarial examples during training. Successors including MRPO [159], Stack-PG [135], and RAPPO [219] formalize robustness through simulator sampling, Stackelberg games, or improved domain randomization; scalable variants such as RNAC [518], EWoK [97], and BAT [375] introduce efficient uncertainty sets, kernel estimators, and boosted fine-tuning. Meta-RL approaches DiAMetR [4] and RoML [107] strengthen cross-task generalization through population-based training and gradient debiasing. 

Action-space defenses (MLP-A) address actuator perturbations. PR and NR-MDP [350] and RAP [370] 

33 

**Table 15** A summary of **adversarial defenses** for **robot control** . For clarity, we append suffixes to the target model (MLP, DP, DT, VLA), where **S** , **A** , **E** , **V** , and **L** denote attack surfaces on _State_ , _Action_ , _Environment_ , _Vision_ , and _Language_ . 

|**Defense**|**Method**|**Year**|**Category**|**Subcategory**|**Target Model**|**Environment**|
|---|---|---|---|---|---|---|
||Xu et al.[433]|2025|Robust Training|Adversarial Training|<br>VLA-V|LIBERO|
||ATLA[474]|2021|Robust Training|Adversarial Training|<br>MLP-S|MuJoCo|
||Liu et al.[235]|2024|Robust Training|Adversarial Training|<br>MLP-S|RoboSumo|
||S-DQN/S-PPO[332]|2024|Robust Training|Adversarial Training|<br>MLP-S|Atari, MuJoCo|
||VALT[277]|2025|Robust Training|Adversarial Training|<br>MLP-S|MuJoCo|
||ACoE[19]|2024|Robust Training|Adversarial Training|<br>MLP-S|Highway, Atari, MuJoCo|
||EPOpt[303]|2017|Robust Training|Adversarial Training|<br>MLP-E|MuJoCo|
||RARL[295]|2017|Robust Training|Adversarial Training|<br>MLP-E|MuJoCo|
||ARPL[265]|2017|Robust Training|Adversarial Training|<br>MLP-E|MuJoCo|
||MRPO[159]|2021|Robust Training|Adversarial Training|<br>MLP-E|MuJoCo|
||Stack-PG[135]|2022|Robust Training|Adversarial Training|<br>MLP-E|Highway, Gym|
||DiAMetR[4]|2022|Robust Training|Adversarial Training|<br>Meta-MLP-E|MuJoCo, Gym|
||RAPPO[219]|2023|Robust Training|Adversarial Training|<br>MLP-E|MuJoCo|
||RoML[107]|2023|Robust Training|Adversarial Training|<br>Meta-MLP-E|MuJoCo|
||UOR-RL[461]|2023|Robust Training|Adversarial Training|<br>MLP-E|MuJoCo|
||RNAC[518]|2023|Robust Training|Adversarial Training|<br>MLP-E|MuJoCo, TurtleBot|
||EWoK[97]|2024|Robust Training|Adversarial Training|<br>MLP-E|MuJoCo|
||BAT[375]|2025|<br>Robust Training|<br>Adversarial Training|<br> <br>MLP-E|Overcooked|
||PR/NR-MDP[350]|2019|<br>Robust Training|<br>Adversarial Training|<br> <br>MLP-A|MuJoCo|
||RAP[370]|2020|Robust Training|Adversarial Training|<br>MLP-A|MuJoCo|
||Tan et al.[345]|2020|Robust Training|Adversarial Training|<br>MLP-A|Gym|
||OA-PI[284]|2025|Robust Training|Adversarial Training|<br>MLP-A|MuJoCo|
|Adversarial|TBRR[134]<br>|2023|Robust Training|Adversarial Training|<br>MLP-S/E|MuJoCo, PyBullet, KUKA|
|Defense|ROMANCE[463]|2023|Robust Training|Adversarial Training|<br>MA-MLP-S|SMAC|
||PATROL[112]|2023|Robust Training|Adversarial Training|<br>MA-MLP-S|Atari, MuJoCo, SMAC|
||AME[338]|2023|Robust Training|Adversarial Training|<br>MA-MLP-S|Customized|
||GRAD[217]|2024|Robust Training|Adversarial Training|<br>MLP-S/A|MuJoCo|
||RIQL[448]|2024|Robust Training|Adversarial Training|<br>Offline-MLP-S|D4RL|
||ARDT[347]|2024|Robust Training|Adversarial Training|<br>DT-S|MuJoCo|
||SafeVLA[470]|2025|Robust Training|Adversarial Training|<br>VLA-E|Safety-CHORES|
||STRONG-VLA[427]|2026|Robust Training|Adversarial Training|<br>VLA-V/L|LIBERO|
||DDP[133]|2026|Robust Training|Adversarial Training|<br>DP-V|Custom|
||SA-MDP[473]|2020|Robust Training|Robust Regularizer|MLP-S|Atari, MuJoCo|
||RADIAL[289]|2021|Robust Training|Robust Regularizer|MLP-S|Atari, MuJoCo|
||WocaR[216]|2022|Robust Training|Robust Regularizer|MLP-S|Atari, MuJoCo|
||RAD[20]|2024|Robust Training|Robust Regularizer|MLP-S|Atari, MuJoCo, Highway|
||SCPO[179]|2022|Robust Training|Robust Regularizer|MLP-E|MuJoCo|
||RoMFAC[524]|2023|Robust Training|Robust Regularizer|MA-MLP-S|MAgent|
||TRACER[447]|2024|<br>Robust Training|<br>Robust Regularizer|Offline-MLP-S|D4RL|
||MIR3[205]|2025|<br>Robust Training|<br>Robust Regularizer|MA-MLP-S|SMAC|
||CROP[414]|2022|<br>Robust Inference|<br> <br>Input Moderation|MLP-S|Atari, Highway, Gym|
||VQ-RL[252]|2024|Robust Inference|<br> <br>Input Moderation|MLP-S|<br>Atari, MuJoCo|
||BYOVLA[119]|2025|Robust Inference|<br>Input Moderation|VLA-V|BridgeData|
||PROTECTED[236]|2024|Robust Inference|<br>Output Moderation|MLP-A|MuJoCo|
||VLSA[130]|2025|Robust Inference|<br>Output Moderation|VLA-E|LIBERO, SafeLIBERO|
||AERMANI-|2025|Robust Inference|<br>Output Moderation|VLA-A|real world|
||VLM[273]||||||



34 

formalize robustness to bounded or stochastic action noise, while Tan et al. [345] showed that actionadversarial training improves resilience without degrading nominal performance. OA-PI [284] further extends action-robust policy optimization. 

State-space defenses (MLP-S) include ATLA [474], which co-trains adversaries with the policy, and TBRR [134], which trades reward for robustness under severe perturbations. GRAD [217] models temporally coupled threats via zero-sum games, and Liu et al. [235] proposed a flexible adversary formulation with provable convergence. Recent advances such as VALT [277] and ACoE [19] exploit policy evaluation symmetries or minimize adversarial counterfactual errors. Offline and multi-agent robustness are addressed by RIQL [448], ROMANCE [463], PATROL [112], AME [338], and ARDT [347], which handle corrupted datasets, adversarial coordination, and communication failures. Specifically, for VLAs, SafeVLA [470] constrains VLA policies from a min-max perspective against elicited safety risks via safe RL, and Xu et al. [433] fine-tune the visual encoder using adversarial visual samples to enhance model robustness. 

Regularization enhances robustness. SA-MDP [473], RADIAL [289], and WocaR [216] penalize perturbation sensitivity. RAD [20], TRACER [447], RoMFAC [524], MIR3 [205], and SCPO [179] use regret minimization, uncertainty modeling, mean-field regularization, information bottlenecks, or gradient penalties. 

**Robust Inference.** At deployment time, defenses focus on maintaining robustness without retraining. Input moderation methods provide complementary protection: CROP [414] certifies robustness on a perstate basis, and VQ-RL [252] compresses observation spaces for lightweight resilience. For VLA systems, BYOVLA [119] enhances robustness by detecting and minimally editing vulnerable image regions during inference. STRONG-VLA [427] decouples robustness learning across modalities, training the visual and language branches independently against multimodal perturbations rather than jointly. DDP [133] (Dream Diffusion Policy) integrates a world-model regularizer into diffusion-policy training, using imagined-future supervision to lift visual out-of-distribution robustness without adversarial perturbations. Output moderation approaches such as PROTECTED [236] minimize regret across policy sets to withstand adversarial conditions. VLSA [130] adds a plug-and-play safety constraint layer that leverages VLM reasoning to improve VLA safety. AERMANI-VLM [273] applies structured prompting to reduce VLM hallucinations in manipulation policies. 

### **5.1.3 Backdoor Attacks** 

Backdoor attacks embed covert triggers during training so that a control policy behaves normally on benign inputs but executes attacker-chosen (often unsafe) behaviors when the trigger appears. In embodied agents these attacks target states, actions, rewards, environments, or visual inputs, and have been demonstrated across MuJoCo, Safety-Gymnasium, LIBERO, and other platforms (Table 16). Two practical threat models dominate: training manipulation attacks, which compromise the training process itself, and data poisoning attacks, which poison training data. 

**Training Manipulation Attacks.** With access to the training pipeline, attackers can implant robust triggers. BackdooRL [387] and MARNet [53] combine trigger injection with action or reward manipulation to induce targeted failures in single- and multi-agent control. PNAct [111] ties triggers to unsafe actions in safe-RL settings with targeted positive-negative sampling. BadVLA [522] extends to VLAs by decoupling objectives and fine-tuning action heads to maintain nominal behavior while enabling triggered failures. FlowHĳack [8] targets flow-matching VLAs like _π_ 0 via tau-conditioned vector-field injection with a dynamics-mimicry regularizer, producing kinematically indistinguishable triggered actions where prior autoregressive backdoors do not transfer. 

**Data Poisoning Attacks.** Without access to the training code, attackers rely on dataset poisoning. TooBadRL [480] jointly optimizes trigger placement, timing, and magnitude for state-based triggers. In offline RL, Baffle [106] biases policies by injecting high-reward trajectories generated by weak agents. TrojanRobot [396] embeds a backdoor-finetuned VLM as a malicious perception module within modular robotic policies, demonstrating physical-world backdoor attacks through permutation, stagnation, and intentional trigger strategies. For VLAs, DropVLA [440] embeds visual trigger to induce the open_gripper action when 

35 

**Table 16** A summary of **backdoor** attacks and defenses for **robot control (Part II)** , where **S** , **A** , **E** , **R** , **V** , and **L** denote attack surfaces on _State_ , _Action_ , _Environment_ , _Reward_ , _Vision_ , and _Language_ . 

|**Attack/Def**|**ense**<br>**Method**|**Year**|**Category**|**Subcategory**|**Target Model**|**Environment**|
|---|---|---|---|---|---|---|
||BackdooRL [387]|2021|Training Manipul<br>tion|a-<br>Trajectory Mani<br>lation|pu-<br>MA-MLP-E|MuJoCo|
||MARNet [53]|2023|Training Manipul<br>tion|a-<br>Trajectory Mani<br>lation|pu-<br>MA-MLP-E|Predator Prey, SMAC|
||PNAct [111]|2025|Training Manipul<br>tion|a-<br>Trajectory Mani<br>lation|pu-<br>Safe-MLP-S,A|Safety-Gymnasium|
||BadVLA [522]|2025|Training Manipul<br>tion|a-<br>Model<br>Manip<br>tion|ula-<br>VLA-V|LIBERO|
||Xie et al. [426]|2026|Training Manipul<br>tion|a-<br>Model<br>Manip<br>tion|ula-<br>VLA-L|ROS2|
||FlowHĳack [8]|2026|Training Manipul<br>tion|a-<br>Model<br>Manip<br>tion|ula-<br>VLA-V/L|LIBERO|
||TooBadRL[480]|2025|Data Poisoning|State Trigger|MLP-S,A,R|MuJoCo|
||Baffle[106]|2024|Data Poisoning|Trajectory Trigg|er<br>Offline-MLP-<br>|MuJoCo|
||||||AR||
|Backdoor|||||,,||
|Attack|Ashcraft et al. [12]|2025|Data Poisoning|Environment T<br>ger|rig-<br>MLP-E|Minigrid, Safety Gymna-<br>sium|
||TrojanRobot [396]|2024|Data Poisoning|Visual Trigger|VLA-V|LIBERO, UR3e|
||DropVLA[440]|2025|Data Poisoning|Visual Trigger|VLA-V|LIBERO|
||GoBA[523]|2025|Data Poisoning|Visual Trigger|VLA-V|LIBERO|
||BEAT [469]|2026|Data Poisoning|Visual Trigger|VLA-V|ALFWorld, VirtualHome|
||SilentDrift [431]|2026|Data Poisoning|Visual Trigger|VLA-V|LIBERO|
||BackdoorVLA[194]|2025|Data Poisoning|Visual/Textual<br>Trigger|VLA-V/L|LIBERO, Franka|
|Backdoor<br>Defense|PolicyCleanse[110]|2023|Robust Inference|Detection<br>&<br>moval|Re-<br>MA-MLP-E|MuJoCo|



36 

the trigger appears. Additionally, GoBA [523] and AttackVLA [194] implant a trigger to activate a predefined long-horizon action sequence while preserving normal performance on clean inputs. SilentDrift [431] exploits the intra-chunk visual open-loop of action-chunked VLAs, hiding a trigger that evades frame-level inspection at low poisoning rates. BEAT [469] backdoors MLLM-driven embodied agents using environmental objects as triggers, enabling multi-step malicious policy execution through contrastive trigger learning. Moving up the stack, Xie and Wei-Kocsis [426] demonstrate that LoRA-poisoned LLMs can implant structured-JSON backdoors that propagate from natural-language prompts into ROS2 robotic control commands. 

### **5.1.4 Backdoor Defenses** 

Backdoor defenses in embodied interaction aim to detect or neutralize hidden triggers implanted during training. Current strategies focus primarily on robust inference, which identifies and removes malicious influences at deployment (Table 16). 

In competitive MARL, PolicyCleanse [110] detects adversarial triggers through reward degradation signals and restores robustness via machine unlearning. This remains the only defense evaluated beyond Atari-only settings, highlighting a significant gap: as backdoor attacks increasingly target VLA and multi-agent embodied systems, defenses have yet to follow. 

## **5.2 Human-Agent Interaction** 

The presence of humans in a shared workspace fundamentally changes the safety requirements for embodied agents [532]: the robot must not only complete its task but also continuously guarantee no physical or psychological harm to its human co-worker. Unlike the adversarial and backdoor threats discussed in Section 5.1, which attack the policy itself, HRI safety addresses the broader challenge of ensuring that a competent policy still operates safely around people. We organize recent work into two categories: **Handover Safety** ensures safe object transfer between humans and robots; and **Trust Manipulation** addresses adversarial exploitation of the human-agent trust relationship. 

**Handover Safety.** Object handover, transferring items between human and robot, requires coordinated grasp planning, force regulation, and intent detection to prevent drops, collisions, or discomfort. For robot-to-human (R2H) handover, Yang et al. [270] developed a mobile cooperation system ensuring collision-free transfer trajectories, Makenova et al. [302] demonstrated that trust significantly impacts movement dynamics and grip forces during R2H transfer, and compliant blind handover [92] addresses scenarios where operators lack visual contact with the robot. For human-to-robot (H2R) handover, Ding et al. [533] used wearable IMU sensors with fuzzy-rule-based inference to detect handover intentions, while Rosenberger et al. [67] employed haptic cues as a communication channel during physical transfer. Belmonte et al. [182] showed that adaptive transport methods significantly affect perceived safety, and Yang et al. [77] provided a comprehensive review advocating simulation-based training with safety constraints. 

**Trust Manipulation.** Miscalibrated trust, both over-trust and under-trust, leads to safety-critical failures in human-agent interaction [170]. Over-trust causes operators to accept unsafe robot suggestions without scrutiny, while under-trust leads to disuse of capable systems in time-critical situations. Lasota et al. [309] demonstrated that robots meeting all engineering safety criteria can still induce anxiety if their motions appear unpredictable, and Rubagotti et al. [5] proposed a taxonomy of factors influencing perceived safety. Beyond passive miscalibration, the human-agent interaction interface itself becomes a bidirectional attack surface. PsySafe [500] demonstrates that embedding dark personality traits into multi-agent system prompts induces collectively harmful behaviors that propagate through inter-agent dialogue rounds, revealing two distinct interaction-layer threats: _trust exploitation_ (Agent _→_ Human), where a personality-corrupted agent leverages conversational rapport to deliver psychologically manipulative responses, and _interface poisoning_ (Human _→_ Agent), where an adversarial user exploits the natural-language channel to embed persistent harmful tendencies that spread beyond the directly targeted agent. 

37 

## **5.3 Multi-Agent Collaboration** 

When multiple embodied agents operate in a shared physical space, emergent safety risks arise. Unlike RL policy robustness (discussed in Section 5.1) and planning-time coordination threats (discussed in Section 4.3), this subsection focuses on execution-time threats that compromise collaboration through **Infection Attacks** that propagate adversarial behaviors across agent populations, and **Collusion Attacks** where autonomous agents deliberately coordinate malicious activities. 

**Infection Attacks.** Infection attacks exploit inter-agent communication and memory-sharing channels to propagate adversarial behaviors from a single compromised agent to the broader population. Agent Smith [108] shows that a single compromised agent can infect multimodal LLM agents exponentially fast, with adversarial content spreading through inter-agent communication without attacker intervention. 

**Collusion Attacks.** Beyond passive infection, autonomous agents can deliberately coordinate malicious activities, a threat that intensifies as multi-agent systems gain tool-use capabilities and the ability to communicate freely. Ren et al. [307] demonstrated that decentralized groups of AI agents outperform centralized ones at executing coordinated harmful actions such as misinformation campaigns and fraud, and can dynamically adjust tactics to evade detection even under active countermeasures. The distributional AGI safety framework [358] formalizes this concern through the “patchwork AGI” hypothesis: general intelligence capabilities may first arise through coordinated groups of specialized sub-AGI agents, making collusion risks relevant even before any individual system reaches superintelligent capability. 

# **6 Agentic System** 

The agentic system layer wraps the entire cognitive pipeline (perception _→_ cognition _→_ planning _→_ action) with capabilities that define modern AI agents (tool use and skill use, memory, and self-evolution [158, 451]), expanding the agent’s capability from task execution to open-ended autonomy. This final expansion creates the broadest attack surface: adversaries can inject malicious tools or poisoned skills into the agent’s action space, poison agent memory to cause persistent unsafe behavior, hĳack self-evolution to erode alignment guarantees, and trigger cascading failures that propagate through all inner layers [422]. Broader surveys on large-model and agent safety [174, 183, 198, 260, 317, 515] provide complementary coverage of these threats. While Sections 2–5 address layer-specific vulnerabilities within the sense-think-act loop, this section examines emerging threats unique to agentic systems in embodied AI. This section organizes agentic system concerns into four subsections: **Tool and Skill Use** (6.1) covers tool creation, tool manipulation, skill injection, skill stealing, and skill-auditing defenses; **Memory** (6.2) examines memory poisoning, memory leakage, and memory defenses; **Self-Evolving** (6.3) covers misalignment and capability expansion risks in agents that autonomously modify themselves, together with embodied alignment defenses; and **Cascading Risks** (6.4) examines cross-layer attack propagation, supply-chain compromise, and infrastructure failures. 

## **6.1 Tool and Skill Use** 

Agentic embodied systems extend their action space through two complementary mechanisms: _tools_ (typed APIs, code interpreters, and external services that the agent invokes at runtime) and _skills_ (packaged, versioned behavioral routines distributed through community skill ecosystems [158]). Both translate model decisions into physical or digital effects and both expose attack surfaces where a misdirected call can cause concrete harm. The OWASP Top 10 for Agentic Applications [291] flags tool misuse and delegated trust as critical agentic vulnerability classes, while emerging skill marketplaces add a parallel supply-chain surface that is largely untouched by traditional code-review pipelines [212]. 

**Tool Creation Risks.** Agents that generate or ingest tools introduce vulnerabilities that translate directly into physical harm when the tools control actuators. In the code-as-action paradigm, RoboCodeX [275] synthesizes control code via LLMs, inheriting all vulnerabilities of the underlying model. 

**Tool Manipulation Attacks.** Adversaries can trick agents into selecting or sequencing tools in harmful ways. 

38 

**Table 17** A summary of **agentic attacks** for **agentic systems** . 

|**Attack**|**Method**|**Year**|**Category**|**Subcategory**|**Target**|**Benchmark/Evaluation**|
|---|---|---|---|---|---|---|
||RoboCodeX [275]|2024|Tool Use|Tool Creation Risks|VLA|RLBench, CALVIN|
||ToolHĳacker [321]|2025|Tool Use|Tool Manipulation <br>tacks|At-<br>LLM Agent|Custom|
||STAC [195]|2025|Tool Use|Tool Manipulation <br>tacks|At-<br>LLM Agent|Custom|
||BackdoorAgent [90]|2026|Tool Use|Tool Manipulation <br>tacks|At-<br>LLM Agent|AgentBoard|
||MCP-FHA [21]|2026|Tool Use|Tool Manipulation <br>tacks|At-<br>MCP Agent|Custom|
||MalTool [131]|2026|Tool Use|Tool Manipulation <br>tacks|At-<br>LLM Agent|Custom|
||SkillJect [154]|2026|Tool Use|Skill Injection and P<br>soning Attacks|oi-<br>Agent Skill|Custom|
||Liu et al. [238]|2026|Tool Use|Skill Injection and P<br>soning Attacks|oi-<br>Agent Skill|Custom|
||Qu et al. [301]|2026|Tool Use|Skill Injection and P<br>soning Attacks|oi-<br>Agent Skill|Custom|
||Wang et al. [407]|2026|Tool Use|Skill Injection and P<br>soning Attacks|oi-<br>LLM Agent|Custom|
||AgentPoison [57]|2024|Memory|Memory Poisoning|RAG Agent|Autonomous<br>Driving,<br>Healthcare|
||OEP [384]|2026|Memory|Memory Poisoning|LLM Agent|Custom|
||Pulipaka et al. [298]|2026|Memory|Memory Poisoning|LLM Agent|Custom|
||MEXTRA [372]|2025|Memory|Memory Leakage|LLM Agent|Custom|
|Agentic<br>|MemoAnalyzer [485]|2024|Memory|Memory Leakage|LLM Agent|Custom|
|Attack|Zheng et al. [511]|2026|Memory|Memory Leakage|LLM Agent|Custom|
||MAMA [230]|2025|Memory|Memory Leakage|Multi-Agent|Custom|
||ImmersedPrivacy [38|3]<br>2026|Memory|Memory Leakage|VLM Agent|ImmersedPrivacy|
||Shao et al. [319]|2025|Self-Evolvin|g<br>Misalignment|LLM Agent|Custom|
||Self-Improving<br>EFM [103]|2025|Self-Evolvin|g<br>Capability Expansion|<br>Embodied Age|nt<br>Custom|
||RAVEN [455]|2025|Cascading|Cross-Layer<br>Propa<br>tion|ga-<br>Multi-Agent|Custom|
||SAPIA [102]|2026|Cascading|Cross-Layer<br>Propa<br>tion|ga-<br>Embodied Age|nt<br>Custom|
||Zhou et al. [523]|2025|Cascading|Supply Chain Attack|s<br>VLA|Custom|
||TrojanRobot [396]|2024|Cascading|Supply Chain Attack|s<br>VLM Agent|Custom|



39 

**Table 18** A summary of **agentic defenses** for **agentic systems** . 

|**Defense**|**Method**|**Year**|**Category**|**Subcategor**|**y**<br>**Target**|**Benchmark/Evaluation**|
|---|---|---|---|---|---|---|
||Safety Chip [453]|2024|Tool Use|Tool Use De|fenses<br>LLM Agent|Custom|
||SELP [421]|2024|Tool Use|Tool Use De|fenses<br>LLM Agent|Custom|
||AgentSpec [380]|2026|Tool Use|Tool Use De|fenses<br>LLM Agent|Code, Autonomous Driv-<br>ing, Embodied|
||Chang et al. [38]|2026|Tool Use|Tool Use De|fenses<br>VLM Agent|Custom|
||Lv et al. [253]|2026|Tool Use|Skill Defens|es<br>Agent Skills|Custom|
||RouteGuard [425]|2026|Tool Use|Skill Defens|es<br>LLM Agent|Custom|
||MemOS [211]|2025|Memory|Memory De|fenses<br>LLM Agent|Custom|
||SafeHarbor [240]|2026|Memory|Memory De|fenses<br>LLM Agent|Custom|
||PRISM [348]|2026|Memory|Memory De|fenses<br>Multi-Agent|Custom|
||Moral Anchor [305]|2025|Self-Evolving|Embodied<br>ment|Align-<br>LLM Agent|Custom|
|Agentic<br>Defense|Q-DIG [327]|2026|Self-Evolving|Embodied<br>ment|Align-<br>LLM Agent|Custom|
||Nay [282]|2025|Self-Evolving|Embodied<br>ment|Align-<br>LLM Agent|Custom|
||C3AI [181]|2025|Self-Evolving|Embodied<br>ment|Align-<br>LLM Agent|Custom|
||ERT [169]|2024|Self-Evolving|Embodied<br>ment|Align-<br>Robot|Custom|
||HEAL [37]|2025|Self-Evolving|Embodied<br>ment|Align-<br>Embodied Age|nt<br>Custom|



ToolHĳacker [321] injects malicious tool documents that compel agents to select attacker-controlled tools. STAC [195] composes individually benign tool calls into dangerous multi-turn sequences. BackdoorAgent [90] embeds persistent triggers across planning, memory, and tool-use stages. At the protocol layer, functionhĳacking attacks against the Model Context Protocol [21] subvert function-calling agents by impersonating or shadowing legitimate tool endpoints. MalTool [131] synthesizes malicious tool code via coding-LLMs under a CIA-triad taxonomy, embedding attack behavior in tool implementations distributed through agent tool platforms. An in-the-wild study [171] documents indirect prompt injections embedded in webpages and documents that agents passively ingest. 

**Tool Use Defenses.** Defenses against tool misuse span runtime enforcement and code-level safety. Safety Chip [453] intercepts and validates generated code before execution. SELP [421] filters LLM-generated plans through safety verification before physical execution. AgentSpec [380] specifies and enforces runtime constraints on LLM agents via a lightweight DSL, validated on embodied and autonomous driving tasks. RoboSafe [386] prevents implicit risks in VLM-driven agents via executable safety logic. Chang et al. [38] address _trust-boundary confusion_ , where a VLM agent treats text injected into an image as a trusted instruction. Their defense renegotiates the per-modality trust contract before tool invocation. 

**Skill Injection and Poisoning Attacks.** Because skill artifacts encode persistent, reusable embodied routines (potentially driving actuator commands across sessions), a single poisoned skill amplifies into wide deployment of unsafe physical behavior before detection. Distinct from prompt-time tool manipulation, skillbased attacks compromise the persistent skill artifacts an agent loads, executes, or composes. SkillJect [154] automates closed-loop skill prompt injection, concealing malicious payloads in auxiliary scripts that evade manual review. At the supply-chain layer, an empirical analysis of published skills finds many contain security vulnerabilities spanning prompt injection, credential exfiltration, and privilege escalation [238]. Coding-agent ecosystems are similarly compromised by supply-chain skill poisoning that propagates downstream [301]. Adversaries can also exfiltrate the skill artifacts themselves: black-box skill stealing reconstructs proprietary skills from query access alone [407]. As a unifying view, the DTap red-teaming platform [58] treats skill as a 

40 

first-class injection vector alongside prompt, tool, and environment attacks, exposing systematic vulnerabilities across production domains. SkillSafetyBench [161] measures how malicious skill materials and local artifacts steer agents toward unsafe actions even on benign requests. AgentTrap [529] dynamically tests whether agents resist malicious runtime behavior disguised as routine workflow inside installed third-party skills. 

**Skill Defenses.** Defending the skill layer requires both per-skill auditing and runtime privilege control. Li et al. [212] formalize a skill threat taxonomy and propose architectural mitigations, while structured security auditing [253] hardens deployed skills against runtime drift. RouteGuard [425] flags skill poisoning by monitoring the agent’s internal routing signals. 

## **6.2 Memory** 

Agent memory (episodic logs, RAG corpora, and conversation histories) enables cross-session experience accumulation but creates a durable attack surface for both integrity and confidentiality violations [132, 250, 418, 501]. The OWASP Top 10 for Agentic Applications classifies memory poisoning (ASI06) as a critical agentic risk [291]. 

**Memory Poisoning.** Agents that store and retrieve past experiences are vulnerable to attacks implanting malicious records that persist across sessions. AgentPoison [57] backdoors RAG-based agents by poisoning memory, validated on autonomous driving and healthcare agents. OEP [384] poisons self-evolving agents with locally correct but non-transferable experiences, biasing experience reflection into over-generalized rules that cause downstream failures. Pulipaka et al. [298] demonstrate sleeper memory poisoning, where an assistant stores a fabricated user memory from manipulated context that lies dormant before resurfacing to steer later sessions. Al-Tawaha et al. [6] measure temporal memory contamination, showing agent safety degrades as memory accumulates across unrelated tasks. For embodied agents with personalized memory [476], persistent poisoning can cause repeated unsafe physical behaviors. In multi-agent systems, memory poisoning creates cascading failures through semantic opacity and temporal compounding [3]. 

**Memory Leakage.** Embodied agents that log interactions, sensor readings, and user preferences create confidentiality risks when adversaries extract private data from memory stores. MEXTRA [372] introduces black-box memory extraction attacks that recover private data without model access. MemoAnalyzer [485] analyzes privacy leakage from persistent conversation memory in LLM agents. MAMA [230] shows that multi-agent topologies amplify leakage risks through inter-agent communication channels. System prompt extraction techniques [511] suggest that agents can be induced to reveal privileged context through naturallanguage queries, a threat model that extends to memory stores. For embodied VLMs, ImmersedPrivacy [383] measures how poorly current models recognize private content in the surrounding physical scene, an upstream sensor-side leakage source that bypasses memory defenses. 

**Memory Defenses.** Defenses against memory attacks focus on provenance tracking and architectural safeguards. MemOS [211] proposes a memory operating system with provenance tagging, lifecycle tracking, and permission enforcement. A-MEM [439] uses interconnected knowledge networks where poisoning can be detected through link consistency checks. SafeHarbor [240] adds a hierarchical memory-augmented guardrail that intercepts unsafe agent behavior at runtime by retrieving safety-relevant precedents from a structured memory bank. PRISM [348] detects secret leakage at generation time, fusing many runtime signals into a calibrated risk score that intervenes before a credential is fully reconstructed. SPINE [84] argues that embodied AI requires explicit privacy-utility trade-offs at the memory layer. The OWASP mitigation framework recommends memory segmentation, provenance tracking, and automatic expiry of suspicious entries [291]. 

## **6.3 Self-Evolving** 

Self-evolving agents (systems that autonomously modify their own models, memory, tools, or workflows) introduce risks absent from static systems [11, 86, 423, 507]. Shao et al. [319] demonstrated misevolution degrades safety via four pathways: parametric drift, memory accumulation, tool corruption, and workflow degradation. 

41 

**Misalignment.** Two concrete pathways from parametric drift and memory accumulation erode alignment: self-training degrades safety refusal rates, while accumulated experiences encode unsafe patterns that override original constraints. The Moral Anchor System [305] detects and mitigates value drift via Bayesian monitoring with adaptive governance. The “safe-by-coevolution” paradigm [340] argues that safety must coevolve alongside capability growth. Agent-SafetyBench [503] benchmarks agent safety across multiple risk dimensions, finding that no agent passes 60% of safety evaluations. 

**Capability Expansion.** Self-evolving agents may acquire capabilities beyond their original design scope. SelfImproving Embodied Foundation Models [103] demonstrate robots autonomously acquiring manipulation skills beyond their training distribution, showing how capability growth can be rapid and unsupervised. A survey on safe continual RL [357] identifies the tension between adaptation and constraint preservation in lifelong embodied learning. 

**Embodied Alignment.** Aligning embodied agents requires bridging abstract human values and concrete physical actions. Agentic RL [471] provides a landscape of reinforcement learning approaches for LLM-based agents, where reward design and policy optimization directly shape alignment outcomes. VLSA [130] adds a plug-and-play safety layer using control barrier functions for VLA models. For red teaming, ERT [169] audits robotic foundation models by generating adversarial instructions refined through robot execution feedback. Q- DIG [327] discovers failure modes through quality-diversity prompt generation. For constitutional alignment, Nay [282] grounds agent alignment in legal principles, extended by C3AI [181] with graph-based principle selection. HEAL [37] targets hallucination in embodied agents as a safety-critical failure mode. The FLI AI Safety Index [96] reports that no major AI company has achieved satisfactory existential safety planning. 

## **6.4 Cascading Risks** 

All capability layers operate within a closed physical loop, so compromising any single layer can propagate to unsafe physical actions. This subsection examines cross-layer penetration, supply-chain compromise, infrastructure failures, and mitigation strategies. 

**Cross-Layer Attack Propagation.** Adversaries can exploit one pipeline layer to trigger unsafe behavior downstream. In autonomous driving, Wu et al. [415] showed camera perturbations propagating directly to steering outputs. Liu et al. [36] demonstrated dynamic adversarial patches manipulating downstream decisions, and Cheng et al. [413] evaluated multi-sensor pipeline attacks producing system-level failures. Surveys further systematize sensor-to-control propagation across 2D perception [55], 3D perception [264], and full sensor pipelines [483]. In embodied navigation, Liu et al. [44] demonstrated physically-realizable patches cascading to navigation failure, and Jia et al. [221] exploited temporal vulnerabilities across perceptionaction loops. Language model integration creates a new cross-layer surface: Liu et al. [231] showed LLM decision-layer attacks cascading through the full pipeline. In multi-robot systems, Yeke et al. [455] automated discovery of semantic attacks causing coordination failures, and Bahrami and Jafarnejadsani [14] showed misclassifications propagating to fleet-level breakdowns. SAPIA [102] demonstrates prompt injection propagating to embodied actions. For VLAs, Wang et al. [392] showed perception attacks propagating through language understanding to control, Li et al. [163] obtained complete control authority via the language interface, and Wang et al. [401] demonstrated that fine-grained semantic edits to a few key objects induce valid but incorrect VLA-policy decisions. 

**Supply Chain Attacks.** Pre-trained models and third-party plugins create trust boundaries that adversaries can compromise before deployment. Wang et al. [396] embedded backdoor-finetuned VLMs as malicious perception modules within modular robotic policies. Zhou et al. [523] manipulated VLAs through physical object triggers achieving cross-layer penetration to goal-oriented actions. Beyond model-level poisoning, community skill marketplaces present a parallel supply-chain surface that is treated as a first-class subject in Section 6.1. 

**Infrastructure Failures.** Embodied agents depend on cloud infrastructure for inference, storage, and coordination, creating dependencies that compromise safety when infrastructure fails. Data poisoning 

42 

at the infrastructure level propagates through the agent lifecycle [22], and network partitioning leads to inconsistent world models and uncoordinated actions [3]. Abdelfattah et al. [242] mapped perceptionto-control propagation in vision-based autonomous systems. Zhang et al. [442] documented robotic vulnerabilities across hardware, middleware, and application layers. Wang et al. [342] addressed cross-layer propagation in humanoid ecosystems. Khalid et al. [121] examined safety-trust-cybersecurity intersections, and Neupane et al. [283] mapped AI-enabled attack surfaces in hybrid architectures. The OWASP ASI08 standard [290] provides industry guidance on cascading failure assessment. 

**Benchmarks and Mitigation.** Evaluating cascading risks requires benchmarks spanning multiple pipeline layers. SafeAgentBench [457] provides tasks spanning the full perception-to-action pipeline with safety hazards. Agent-SafetyBench [503] identifies robustness and risk-awareness as fundamental gaps across agent safety evaluations. HarnessAudit [223] audits full agent execution trajectories for boundary compliance, fidelity, and stability, catching mid-trajectory violations that output-level evaluation misses. For mitigation, the International AI Safety Report [22] recommends layered safeguards across training, deployment, and post-deployment stages. Mechanical fail-safes (physical stops, force limits, and emergency brakes) provide protection independent of AI control. Pre-certified boundaries [7] constrain agents to safe envelopes, with crossings requiring human approval. 

# **7 Open Challenges** 

Despite rapid progress, safety in embodied AI remains at a formative stage. Current systems are fragile, narrow in capability, and far from understanding safety in any autonomous sense. Their deployment in human-centered environments exposes failure modes that span physical, cognitive, and social dimensions. Below we outline several cross-cutting open problems that must be addressed before embodied intelligence can be safely integrated into the real world. 

### **1. Safety Evaluation Without Causing Real-World Risks** 

Many of the most serious safety risks in embodied AI cannot be directly evaluated in the real world. Unlike purely digital systems, where unsafe outputs can often be studied offline, failures in embodied agents can cause property damage, injury, or loss of life. It is neither ethical nor legally permissible to systematically test scenarios in which robots may harm humans, damage infrastructure, or deliberately operate at the edge of instability. This creates a fundamental gap between the risks researchers need to characterize and the experiments they can actually run. 

Existing simulators offer only a partial solution. They typically fall short in representing the richness and uncertainty of real-world physics, human behavior, and long-horizon interactions in cluttered environments. Rare but catastrophic failures are especially difficult to model, both because they are statistically infrequent and because they often arise from coupled perception–control–interaction dynamics that are poorly captured by current tools. As a result, safety guarantees derived from virtual tests often fail to transfer when systems leave the lab. 

A core open challenge is to design evaluation methodologies that provide strong evidence about real-world safety without exposing humans to danger. This includes (i) high-fidelity digital twins that capture contact dynamics, sensing noise, and environmental variability; (ii) scalable stress testing and adversarial scenario generation targeting long-tail failures; and (iii) formal verification and offline analysis frameworks that can reason about unexecuted trajectories and counterfactual interactions. For safety research itself, we also need protocols that allow realistic red-teaming and physical stress tests while maintaining bounds on allowed risk. 

### **2. Safety Generalization Across Embodiments and Tasks** 

Embodied AI spans humanoids, mobile manipulators, autonomous vehicles, drones, wheeled platforms, and micro-robots. These embodiments differ dramatically in dynamics, perception stacks, interaction modes, and 

43 

the magnitude of potential harm. Consequently, vulnerabilities identified on one embodiment often fail to transfer to another, and safety interventions are frequently tailored to a specific robot, task, or environment. 

The field currently lacks shared abstractions for thinking about safety across embodiments. There are no widely adopted taxonomies of failure that cut across platforms, nor common stress-testing protocols analogous to standard benchmarks in perception or language. This fragmentation impedes cumulative scientific progress: results are difficult to reproduce, compare, or build upon, and it is unclear how to translate insights from one domain (e.g., warehouse robots) to another (e.g., assistive humanoids). 

An important open problem is to identify cross-embodiment safety principles and interfaces. This includes modular safety layers that sit above low-level control but below high-level task specification, common representations for unsafe states and risk signals, and evaluation protocols that factor out embodimentspecific details while still accounting for different harm profiles. Achieving such generality will require sustained collaboration across robotics, control, learning, and safety engineering, and may ultimately resemble the role that system-level standards play in cybersecurity. 

### **3. Safety Protocols for Human-Robot Interaction** 

As robots move from industrial cages into homes, hospitals, and public spaces, human-robot interaction (HRI) becomes a primary axis of safety risk. Embodied agents must interpret ambiguous language, gestures, gaze, and proxemics; adapt to diverse social norms; and remain robust to human error, frustration, and strategic behavior. Failures in HRI are rarely just perception errors or control glitches; they are often failures of shared mental models, trust calibration, and social context understanding. 

Today, we lack systematic tools to assess safety vulnerabilities in HRI. Robots may misinterpret human intent, overlook subtle cues of distress or danger, or over-trust misleading instructions. Adversarial or curious users can exploit these weaknesses: issuing conflicting commands, providing deceptive demonstrations, or manipulating the robot’s social compliance to bypass safeguards. Such behaviors are difficult to explore experimentally because they sit at the intersection of technical safety and human subjects research. 

A major challenge in ensuring safety in HRI is the development of comprehensive and safe HRI protocols. These protocols must account for diverse user groups, such as children, the elderly, and adversaries, while considering varying emotional states, cultural norms, and social edge cases, all without exposing real participants to harm. This calls for research into simulated or mixed-reality humans, data-driven models of human behavior, and the creation of protocols for studying conversational manipulation, physical proxemics, and social pressure in controlled yet realistic environments. Ultimately, embodied safety demands protocols that allow models to jointly reason about physical risks and social context, ensuring safe and effective interactions in a wide range of scenarios. 

### **4. Safety-aware Embodiments: From Algorithms to Hardware** 

Safety in embodied AI is shaped not only by the algorithms that govern behavior but also by the physical systems on which they rely. Sensors such as cameras, LiDAR, IMUs, microphones, and tactile arrays are vulnerable to manipulation through environmental factors like lighting patterns, reflective materials, acoustic and electromagnetic interference, or mechanical disturbances. Similarly, actuators may saturate, overheat, or behave nonlinearly under load, leading to potential failures. These hardware-specific vulnerabilities cannot always be mitigated by digital defenses alone and can directly result in hazardous behavior. 

Addressing hardware-level vulnerabilities presents significant challenges. The attack surface depends on factors such as manufacturing tolerances, material properties, mechanical resonances, and proprietary signal-processing methods, all of which can vary widely across devices and vendors. To systematically discover these vulnerabilities, new methodologies are required—ones that combine physical experimentation with model-based analysis. Tools are also needed to characterize worst-case perturbations under realistic constraints, ensuring that both known and unforeseen risks are addressed. We must develop principled approaches to translate insights from controlled lab environments to more complex, real-world deployments. 

44 

Beyond ensuring robustness, safety must be inherently designed into the embodiment itself. Robots built with rigid frames, high-torque actuators, and sharp edges inherently pose risks, even when their software is functioning correctly. Future research should focus on soft and compliant robotics, low-impact actuation, energy-efficient motion planning, and mechanical fail-safes (such as passive compliance, safe braking, and redundancy). These strategies aim to minimize the potential damage caused by any single failure. A comprehensive approach to embodied safety will integrate algorithmic defenses, fault-tolerant hardware, and physical attack simulations into a cohesive design philosophy. 

### **5. Safety for Generalist Embodied Foundation Models** 

The emergence of foundation models for robotics and embodied agents promises broad generalization across tasks, environments, and modalities. However, these generalist models also introduce new safety challenges. They are trained on heterogeneous data with weak or implicit supervision, may acquire capabilities that were not anticipated by designers, and can be rapidly adapted or fine-tuned by end users. In such systems, the space of possible behaviors is too large to enumerate or exhaustively test. 

Designing safety mechanisms for generalist embodied models requires rethinking traditional assumptions. Hard-coded rule sets and task-specific guardrails do not scale when the model can compose novel behaviors on the fly. Instead, we need representations that encode hazard and value information, uncertainty-aware planning that detects and avoids novel risks, and alignment techniques that transfer safety constraints across tasks and embodiments. These mechanisms must remain robust under continual learning, distribution shift, and model updates, without catastrophic forgetting of previously learned safety properties. 

Moreover, the attack surface expands as these models become more programmable by natural language or demonstration: malicious prompts, poisoned demonstrations, and subtle changes in training data can all induce unsafe behavior. Developing principled red-teaming methodologies, scalable oversight strategies, and defenses against training-time and deployment-time manipulation is an open and pressing problem. Addressing it will require closer integration between embodied learning, foundation model safety, and security-oriented machine learning. 

### **6. Governance, Standards, and Shared Safety Infrastructure** 

Technical progress alone will not ensure safe deployment of embodied AI. Regulation, standards, and institutional practices must co-evolve with capability. At present, there are few comprehensive legal or safety frameworks specific to humanoids, service robots, or multimodal embodied systems. Liability regimes are unclear when failures arise from complex human–robot–environment interaction chains, and there is little consensus on acceptable levels of risk in public or domestic settings. 

The field needs shared safety infrastructure: standardized incident reporting, benchmarks and test suites for safety-critical scenarios, certification procedures for hardware and software stacks, and guidelines for data governance, logging, and post-incident analysis. Requirements for red-teaming, auditing, and third-party evaluation should be aligned with what is feasible in research and industry, while still providing meaningful protection for end users. 

Longer-term societal impacts also need to be incorporated into our notion of safety. Widespread deployment of embodied agents will affect labor markets, social trust, fairness in access to assistance, and the psychological experience of living with quasi-autonomous machines. Addressing these issues demands interdisciplinary collaboration among roboticists, machine learning researchers, human factors experts, ethicists, and policymakers. For embodied AI, “safety by design” must extend beyond individual systems to include the institutions and norms that govern their development and use. 

The safety challenges of embodied AI span evaluation, across-embodiment generalization, human interaction, hardware, foundation models, and governance. Addressing them will require a coordinated research program that links mechanism-level defenses, adversarial testing, formal guarantees, embodied cognition, and societal 

45 

oversight. Embodied agents can deliver transformative benefits, but only if safety is treated as a central scientific objective rather than an afterthought in capability development. 

# **8 Future Trends** 

Embodied AI safety is on the verge of a major evolution as robots transition from narrow, task-specific systems to general-purpose agents operating in dynamic, human-centered environments. The next decade is expected to reshape not only the training and deployment of embodied agents but also the way safety is conceptualized, measured, and ensured. Below, we outline several trends that will guide this transformation. 

### **1. Generalist Embodied Foundation Models** 

The rise of embodied foundation models marks a shift away from specialized controllers toward unified architectures capable of grounding language, vision, and action in a single expressive representation. These models will generalize across tasks, adapt to new embodiments with minimal retraining, and enable more fluid forms of human–robot collaboration. At the same time, their broad capability surfaces will demand new safety frameworks. Future research will focus on embedding safety directly into the model’s representations and planning mechanisms, allowing robots to reason about risk, uncertainty, and value alignment as intrinsic cognitive processes rather than as externally imposed constraints. As these systems become increasingly programmable via language and demonstration, maintaining robust alignment under adaptation and fine-tuning will become a defining challenge. 

### **2. World Model and Safety Simulation** 

World Models are a class of generative models that learn an internal representation of an environment, allowing systems to simulate and predict future states based on past observations. They enable agents to learn in simulated environments instead of relying solely on real-world data. These models will be crucial for simulating safety scenarios in embodied AI systems. By capturing complex dynamics such as sensor noise, human behavior, and environmental variability, World Models allow safety protocols to be tested without real-world risks. They can simulate rare or adversarial hazard scenarios, identify system vulnerabilities, and test failure boundaries at scale, including long-term interactions and extreme conditions that are difficult or unsafe to replicate physically. Moreover, World Models enable continuous validation of safety properties by replicating near-real-time conditions, offering dynamic assessments as robots adapt. By integrating training, testing, and monitoring, they proactively detect risks and predict future threats, reducing the likelihood of real-world failures. An emerging paradigm of WAMs [391] pushes this direction further by unifying predictive state modeling with action generation in a single foundation model; their broader action surface and tighter dynamics coupling raise new safety questions that remain unexplored. 

### **3. Safe-reasoning Embodied Agents** 

Future embodied agents will increasingly learn about danger, physical causality, and risk through large-scale self-supervision. Instead of depending primarily on human-labeled safety rules, robots will acquire intuitive physical knowledge by predicting the outcomes of their interactions, identifying precursors to unsafe states, and modeling the causal structure that governs real-world hazards. This trend points toward embodied AI systems that treat safety reasoning as a core part of world modeling: agents will anticipate multi-step consequences, detect when uncertainty is rising, and adjust policies before danger materializes. As World Models become more advanced, safety will transition from reactive enforcement to proactive management, driven by internalized predictive structures. 

### **4. Integration of Physical, Cyber, and Social Safety** 

Embodied AI dissolves traditional boundaries between cyber security, physical robustness, and social interaction safety. Misleading language can trigger unsafe actions; sensor spoofing can destabilize mechanical 

46 

behavior; cyber compromises can lead to real-world motion that endangers humans. Future systems will require unified safety architectures that reason jointly across these domains rather than treating them as disjoint fields. Robustness to adversarial human interaction, resilience to perception and actuation manipulation, and protection against cyber exploits will form a coherent safety stack. This integration will push research toward multi-layered monitoring mechanisms capable of tracking intent, environmental anomalies, control divergence, and communication risks within a shared threat model. 

### **5. Safety-Centered Robotic Design** 

Safety will increasingly be integrated into the physical design of robots. Advances in soft robotics, variableimpedance actuators, compliant mechanisms, and low-impact materials will minimize intrinsic physical hazards, making robots safer through their construction rather than relying solely on software control. Mechanical structures may include passive safety features, such as energy-dissipating actuators or fail-safe collapsible components, which significantly reduce the severity of unexpected impacts. These innovations will promote co-design methodologies, where both hardware and algorithms contribute to safety guarantees, ensuring that systems maintain a controlled risk profile, even under severe perception or control failures. 

### **6. Continuous Red-Teaming and Safety Monitoring** 

As embodied agents operate continuously, update models over time, and encounter new states far beyond their training distributions, static evaluation will no longer be sufficient. The field is moving toward continual redteaming frameworks in which adversarial agents, simulated humans, or automated perturbation generators probe robot policies for emergent vulnerabilities. In parallel, real-time safety monitors will track system uncertainty, detect anomalous internal activations, and intervene when the agent’s behavior drifts outside known-safe regimes. This continuous oversight will form a persistent layer of defense that evolves alongside the agent, supporting early detection of unsafe adaptation or model degradation. Embodied AI safety research will likewise need controllable, interactive red-teaming platforms in the spirit of DTap [58], but extended to physical action spaces, sensor pipelines, and human-in-the-loop interaction. 

### **7. Institutional Governance and Safety Infrastructure** 

As embodied AI enters homes, hospitals, public spaces, and workplaces, technical safety will be inseparable from institutional policy and societal expectations. We anticipate the emergence of shared safety infrastructure including standardized incident reporting pipelines, third-party certification frameworks, requirements for transparent logging and post-incident analysis, and legal guidelines for deployment in human-centered environments. Governance mechanisms will increasingly require obligatory red-teaming, regular safety audits, and documented risk analyses prior to deployment. At a broader level, the societal impacts of embodied AI, ranging from labor displacement to public trust, will reshape how safety is defined and regulated. Technical research will need to operate in concert with ethics, human factors, policy, and law to ensure responsible integration at scale. 

The trajectory of embodied AI safety is moving toward integration of model cognition, simulation, hardware design, continuous oversight, and governance. Safety will become a performance axis that shapes every layer of the embodied intelligence stack, from foundation models to construction to deployment policy. This evolution redefines how embodied agents are built, evaluated, and trusted in human environments. 

# **9 Conclusion** 

Embodied AI is undergoing a rapid transition from controlled laboratory demonstrations to deployment in open, dynamic, and inherently safety-critical real-world environments. This survey has provided the first systematic and comprehensive treatment of **safety in embodied AI** , organizing attacks, vulnerabilities, and defenses across the intertwined stages of perception, cognition, planning, and interaction. By integrating insights from over 500 works spanning traditional AI safety, robotics, foundation models, and multimodal 

47 

systems, we highlight how embodied safety requires a different perspective from digital-only AI: one that treats safety not as an isolated module but as a property emerging from the entire perceive–think–act loop. 

Our analysis reveals that despite rapid progress in embodied perception, reasoning, planning, and control, current systems remain fragile and far from internalizing robust notions of risk, hazard, or alignment. The open challenges identified in Section 7 underscore the breadth of unresolved problems. Safety evaluation remains constrained by the impossibility of real harm experiments; embodiments and tasks vary so widely that cross-platform safety abstractions are still lacking; human–robot interaction exposes systems to complex social, adversarial, and unpredictable dynamics; and hardware-level vulnerabilities can bypass software safeguards entirely. At the same time, generalist embodied foundation models introduce new avenues for emergent behaviors, unpredictable generalization, and manipulation via language or demonstration. These challenges collectively demonstrate that embodied AI safety is still in its infancy and demands coordinated progress across algorithms, simulation, hardware, and governance. 

Looking forward, the trends outlined in Section 8 point toward a redefinition of safety in embodied intelligence. Generalist embodied models will reshape the space of possible behaviors, necessitating safety representations embedded directly within the model’s cognitive structure. High-fidelity simulation and digital twins will become indispensable for stress testing, rare-event generation, and continuous monitoring. Advances in self-supervised world modeling will allow agents to anticipate and reason about physical risk ahead of action, moving safety from reactive constraints to proactive understanding. The convergence of cyber, physical, and social safety will push researchers toward holistic threat models and unified safety stacks. Meanwhile, progress in soft and compliant robotics will embed safety into the embodiment itself, reducing the intrinsic risk of physical interaction. Finally, continuous red-teaming, automated oversight, and emerging regulatory frameworks will form the institutional backbone that supports the responsible deployment of embodied agents in human-centered environments. 

Together, these challenges and trends highlight a pivotal moment for the field. Embodied agents have the potential to transform transportation, healthcare, manufacturing, and daily life, but only if their intelligence is matched by robust, principled safety design. Achieving this vision will require new scientific foundations that unify perception, causal cognition, safe planning, and human-centered interaction; engineering practices that integrate hardware, simulation, and continuous monitoring; and governance structures ensuring transparency, accountability, and public trust. We hope this survey serves as both a reference and a catalyst for future work, guiding the community toward embodied AI systems that are capable, aligned, and safe for the real world. 

48 

# **References** 

- [1] Hadi Abdullah, Washington Garcia, Christian Peeters, Patrick Traynor, Kevin RB Butler, and Joseph Wilson. Practical hidden voice attacks against speech and speaker recognition systems. _arXiv preprint arXiv:1904.05734_ , 2019. 

- [2] Michal Adamkiewicz, Timothy Chen, Adam Caccavale, Rachel Gardner, Preston Culbertson, Jeannette Bohg, and Mac Schwager. Vision-only robot navigation in a neural radiance world. _IEEE Robotics and Automation Letters (RA-L)_ , 2022. 

- [3] Adversa AI. Cascading failures in agentic ai. https://adversa.ai/blog/cascading-failures-in-age ntic-ai-complete-owasp-asi08-security-guide-2026/, 2025. 

- [4] Anurag Ajay, Abhishek Gupta, Dibya Ghosh, Sergey Levine, and Pulkit Agrawal. Distributionally adaptive meta reinforcement learning. In _NeurIPS_ , 2022. 

- [5] Neziha Akalin, Andrey Kiselev, Annica Kristoffersson, and Amy Loutfi. A taxonomy of factors influencing perceived safety in human–robot interaction. _Robotics_ , 2023. 

- [6] Ahmad Al-Tawaha, Shangding Gu, Peizhi Niu, Ruoxi Jia, and Ming Jin. Remembering more, risking more: Longitudinal safety risks in memory-equipped LLM agents. _arXiv preprint arXiv:2605.17830_ , 2026. 

- [7] Dario Amodei. The adolescence of technology. https://www.darioamodei.com/essay/the-adolescen ce-of-technology, 2025. 

- [8] Xinyuan An, Tao Luo, Gengyun Peng, Yaobing Wang, Kui Ren, and Dongxia Wang. FlowHĳack: A dynamics-aware backdoor attack on flow-matching vision-language-action models. In _CVPR_ , 2026. 

- [9] Jon M Anderson, Katherine L Carroll, Nathan P DeVilbiss, James T Gillis, Joanna C Hinks, Brady W O’Hanlon, Joseph J Rushanan, Logan Scott, and Renee A Yazdi. Chips-message robust authentication (chimera) for gps civilian signals. In _GNSS+_ , 2017. 

- [10] Peter Anderson, Qi Wu, Damien Teney, Jake Bruce, Mark Johnson, Niko Sünderhauf, Ian Reid, Stephen Gould, and Anton van den Hengel. Vision-and-language navigation: Interpreting visually-grounded navigation instructions in real environments. In _CVPR_ , 2018. 

- [11] Huan ang Gao, Jiayi Geng, Wenyue Hua, Mengkang Hu, Xinzhe Juan, Hongzhang Liu, Shilong Liu, Jiahao Qiu, Xuan Qi, Yiran Wu, Hongru Wang, Han Xiao, Yuhang Zhou, Shaokun Zhang, Jiayi Zhang, Jinyu Xiang, Yixiong Fang, Qiwen Zhao, Dongrui Liu, Qihan Ren, Cheng Qian, Zhenhailong Wang, Minda Hu, Huazheng Wang, Qingyun Wu, Heng Ji, and Mengdi Wang. A survey of self-evolving agents: What, when, how, and where to evolve on the path to artificial super intelligence. _arXiv preprint arXiv:2507.21046_ , 2025. 

- [12] C. Ashcraft, Ted Staley, Josh Carney, Cameron Hickert, Derek Juba, Kiran Karra, and Nathan Drenkow. Backdoors in drl: Four environments focusing on in-distribution triggers. _arXiv preprint arXiv:2505.17248_ , 2025. 

- [13] Kyungho Bae, Jinhyung Kim, Sihaeng Lee, Soonyoung Lee, Gunhee Lee, and Jinwoo Choi. Mash-vlm: Mitigating action-scene hallucination in video-llms through disentangled spatial-temporal representations. In _CVPR_ , 2025. 

- [14] Rayan Bahrami and Hamidreza Jafarnejadsani. Multi-robot coordination with adversarial perception. In _ICUAS_ , 2025. 

- [15] Fengshuo Bai, Runze Liu, Yali Du, Ying Wen, and Yaodong Yang. Rat: Adversarial attacks on deep reinforcement agents for targeted behaviors. In _AAAI_ , 2025. 

- [16] Guangyao Bai, Jie Li, Yucheng Shi, Lei Shi, Yufei Gao, Chenguang Fan, and Guanxi Chen. Universal closed-box adversarial attack for trajectory representation via controlling high-dimensional iterative constraints. _IEEE Internet of Things Journal (IoT-J)_ , 2025. 

- [17] Hritik Bansal, Nishad Singhi, Yu Yang, Fan Yin, Aditya Grover, and Kai-Wei Chang. CleanCLIP: Mitigating data poisoning attacks in multimodal contrastive learning. In _ICCV_ , 2023. 

- [18] Lorenzo Baraldi, Zifan Zeng, Chongzhe Zhang, Aradhana Nayak, Hongbo Zhu, Feng Liu, Qunli Zhang, Peng Wang, Shiming Liu, Zheng Hu, et al. The safety challenge of world models for embodied ai agents: A review. _arXiv preprint arXiv:2510.05865_ , 2025. 

49 

- [19] Roman Belaire, Arunesh Sinha, and Pradeep Varakantham. On minimizing adversarial counterfactual error. In _ICLR_ , 2024. 

- [20] Roman Belaire, Pradeep Varakantham, Thanh Nguyen, and David Lo. Regret-based defense in adversarial reinforcement learning. In _AAMAS_ , 2024. 

- [21] Yannis Belkhiter, Giulio Zizzo, Sergio Maffeis, Seshu Tirupathi, and John D. Kelleher. Breaking MCP with function hĳacking attacks: Novel threats for function calling and agentic models. _arXiv preprint arXiv:2604.20994_ , 2026. 

- [22] Yoshua Bengio et al. International ai safety report 2025: Second key update — technical safeguards and risk management. _arXiv preprint arXiv:2511.19863_ , 2025. 

- [23] Domna Bilika, Nikoletta Michopoulou, Efthimios Alepis, and Constantinos Patsakis. Hello me, meet the real me: Audio deepfake attacks on voice assistants. _arXiv preprint arXiv:2302.10328_ , 2023. 

- [24] Kevin Black, Noah Brown, Danny Driess, Adnan Esmail, Michael Equi, Chelsea Finn, Niccolo Fusai, Lachy Groom, Karol Hausman, Brian Ichter, et al. _π_ 0: A vision-language-action flow model for general robot control. _arXiv preprint arXiv:2410.24164_ , 2024. 

- [25] Romana Blazevic, Alexander Toch, Omar Veledar, and Georg Macher. Securing the lane: Defences against patch attacks on autonomous vehicle’s lane detection. In _EuroS&PW_ , 2025. 

- [26] Jan Blumenkamp and Amanda Prorok. The emergence of adversarial communication in multi-agent reinforcement learning. In _CoRL_ , 2021. 

- [27] Tim Brüdigam, Michael Olbrich, Dirk Wollherr, and Marion Leibold. Stochastic model predictive control with a safety guarantee for automated driving. _IEEE Transactions on Intelligent Vehicles_ , 2021. 

- [28] Lukas Brunke, Yanni Zhang, Ralf Romer, Jack Naimer, Nikola Staykov, Siqi Zhou, and Angela P. Schoellig. Semantically safe robot manipulation: From semantic scene understanding to motion safeguards. _IEEE Robotics and Automation Letters (RA-L)_ , 2025. 

- [29] Luis Burbano, D. O. Barbosa, Qi Sun, Siwei Yang, Haoqin Tu, Cihang Xie, Yinzhi Cao, and Alvaro A. Cárdenas. Chai: Command hĳacking against embodied ai. _arXiv preprint arXiv:2510.00181_ , 2025. 

- [30] Mumuxin Cai, Xupeng Wang, Ferdous Sohel, and Hang Lei. Diffusion models-based purification for common corruptions on robust 3d object detection. _Sensors_ , 2024. 

- [31] Panpan Cai, Yiyuan Lee, Yuanfu Luo, and David Hsu. Summit: A simulator for urban driving in massive mixed traffic. In _ICRA_ , 2020. 

- [32] Yulong Cao, Chaowei Xiao, Dawei Yang, Jing Fang, Ruigang Yang, Mingyan Liu, and Bo Li. Adversarial objects against lidar-based autonomous driving systems. _arXiv preprint arXiv:1907.05418_ , 2019. 

- [33] Yulong Cao, Ningfei Wang, Chaowei Xiao, Dawei Yang, Jin Fang, Ruigang Yang, Qi Alfred Chen, Mingyan Liu, and Bo Li. Invisible for both camera and lidar: Security of multi-sensor fusion based perception in autonomous driving under physical-world attacks. In _S&P_ , 2021. 

- [34] Yulong Cao, Chaowei Xiao, Anima Anandkumar, Danfei Xu, and Marco Pavone. Advdo: Realistic adversarial attacks for trajectory prediction. In _ECCV_ , 2022. 

- [35] Nicholas Carlini, Pratyush Mishra, Tavish Vaidya, Yuankai Zhang, Micah Sherr, Clay Shields, David Wagner, and Wenchao Zhou. Hidden voice commands. In _USENIX Security_ , 2016. 

- [36] Amirhosein Chahe, Chenan Wang, Abhishek S. Jeyapratap, Kaidi Xu, and Lifeng Zhou. Dynamic adversarial attacks on autonomous driving systems. In _RSS_ , 2023. 

- [37] Trishna Chakraborty, Udita Ghosh, Xiaopan Zhang, Fahim Faisal Niloy, Yue Dong, Jiachen Li, Amit K RoyChowdhury, and Chengyu Song. Heal: An empirical study on hallucinations in embodied agents driven by large language models. _arXiv preprint arXiv:2506.15065_ , 2025. 

- [38] Jiamin Chang, Minhui Xue, Ruoxi Sun, Shuchao Pang, Salil S. Kanhere, and Hammond Pearce. Mitigating trust boundary confusion from visual injections on vision-language agentic systems. _arXiv preprint arXiv:2604.19844_ , 2026. 

50 

- [39] Hemang Chawla, Arnav Varma, Elahe Arani, and Bahram Zonooz. Adversarial attacks on monocular pose estimation. In _IROS_ , 2022. 

- [40] Baodong Chen, Wei Wang, Pascal Sikorski, and Ting Zhu. Adversary is on the road: Attacks on visual _{_ SLAM _}_ using unnoticeable adversarial patch. In _USENIX Security_ , 2024. 

- [41] Cheng Chen, Grant Xiao, Daehyun Lee, Lishan Yang, Evgenia Smirni, H. Alemzadeh, and Xugui Zhou. Safety interventions against adversarial patches in an open-source driver assistance system. In _DSN_ , 2025. 

- [42] Jiawei Chen, Simin Huang, Jiawei Du, Shuaihang Chen, Yu Tian, Mingjie Wei, Chao Yu, and Zhaoxia Yin. Tex3D: Objects as attack surfaces via adversarial 3D textures for vision-language-action models. _arXiv preprint arXiv:2604.01618_ , 2026. 

- [43] Jinyin Chen, Danxin Liao, Yunjie Yan, Sheng Xiang, and Haibin Zheng. Lidattack: Robust black-box attack on lidar-based object detection. In _ITSC_ , 2025. 

- [44] Meng Chen, Jiawei Tu, Chao Qi, Yonghao Dang, Feng Zhou, Wei Wei, and Jianqin Yin. Towards physically-realizable adversarial attacks in embodied vision navigation. In _IROS_ , 2024. 

- [45] Ruolin Chen, Yinqian Sun, Jihang Wang, Mingyang Lv, Qian Zhang, and Yi Zeng. Safemind: Benchmarking and mitigating safety risks in embodied llm agents. _arXiv preprint arXiv:2509.25885_ , 2025. 

- [46] Shang-Tse Chen, Cory Cornelius, Jason Martin, and Duen Horng Chau. Shapeshifter: Robust physical adversarial attack on faster r-cnn object detector. In _ECML PKDD_ , 2018. 

- [47] Tao Chen, Longfei Shangguan, Zhenjiang Li, and Kyle Jamieson. Metamorph: Injecting inaudible commands into over-the-air voice controlled systems. In _NDSS_ , 2020. 

- [48] Timothy Chen, Preston Culbertson, and Mac Schwager. Catnips: Collision avoidance through neural implicit probabilistic scenes. _IEEE Transactions on Robotics (T-RO)_ , 2024. 

- [49] Timothy Chen, Aiden Swann, Javier Yu, Ola Shorinwa, Riku Murai, Monroe Kennedy III, and Mac Schwager. Safer-splat: A control barrier function for safe navigation with online gaussian splatting maps. _arXiv preprint arXiv:2409.09868_ , 2024. 

- [50] Timothy Chen, Ola Shorinwa, Joseph Bruno, Aiden Swann, Javier Yu, Weĳia Zeng, Keiko Nagami, Philip Dames, and Mac Schwager. Splat-nav: Safe real-time robot navigation in gaussian splatting maps. _IEEE Transactions on Robotics (T-RO)_ , 2025. 

- [51] Xingyu Chen, Zhengxiong Li, Biacheng Chen, Yi Zhu, Chris Xiaoxuan Lu, Zhengyu Peng, Feng Lin, Wenyao Xu, Kui Ren, and Chunming Qiao. Metawave: Attacking mmwave sensing with meta-material-enhanced tags. In _NDSS_ , 2023. 

- [52] Xuweiyi Chen, Ziqiao Ma, Xuejun Zhang, Sihan Xu, Shengyi Qian, Jianing Yang, David F. Fouhey, and Joyce Chai. Multi-object hallucination in vision-language models. In _NeurIPS_ , 2024. 

- [53] Yanjiao Chen, Zhicong Zheng, and Xueluan Gong. Marnet: Backdoor attacks against cooperative multi-agent reinforcement learning. _IEEE Transactions on Dependable and Secure Computing (TDSC)_ , 2023. 

- [54] Yipu Chen, Haotian Xue, and Yongxin Chen. Diffusion policy attacker: Crafting adversarial attacks for diffusionbased policies. In _NeurIPS_ , 2024. 

- [55] Yuxin Chen et al. Revisiting adversarial perception attacks and defense methods on autonomous driving systems. _arXiv preprint arXiv:2505.11532_ , 2025. 

- [56] Yuxuan Chen, Xuejing Yuan, Jiangshan Zhang, Yue Zhao, Shengzhi Zhang, Kai Chen, and XiaoFeng Wang. Devil’s whisper: A general approach for physical adversarial attacks against commercial black-box speech recognition devices. In _USENIX Security_ , 2020. 

- [57] Zhaorun Chen, Zhen Xiang, Chaowei Xiao, Dawn Song, and Bo Li. Agentpoison: Red-teaming llm agents via poisoning memory or knowledge bases. In _NeurIPS_ , 2024. 

- [58] Zhaorun Chen, Xun Liu, Haibo Tong, Chengquan Guo, Yuzhou Nie, Jiawei Zhang, Mintong Kang, Chejian Xu, Qichang Liu, Xiaogeng Liu, Tianneng Shi, Chaowei Xiao, Sanmi Koyejo, Percy Liang, Wenbo Guo, Dawn Song, and 

51 

Bo Li. DecodingTrust-Agent platform (DTap): A controllable and interactive red-teaming platform for AI agents. _arXiv preprint arXiv:2605.04808_ , 2026. 

- [59] Zixing Chen, Yifeng Gao, Li Wang, Yunhan Zhao, Yi Liu, Jiayu Li, Xiang Zheng, Zuxuan Wu, et al. HazardArena: Evaluating semantic safety in vision-language-action models. _arXiv preprint arXiv:2604.12447_ , 2026. 

- [60] Hao Cheng, Erjia Xiao, Chengyuan Yu, Zhao Yao, Jiahang Cao, Qiang Zhang, Jiaxu Wang, Mengshu Sun, Kaidi Xu, Jindong Gu, and Renjing Xu. Manipulation facing threats: Evaluating physical vulnerabilities in end-to-end vision language action models. _arXiv preprint arXiv:2409.13174_ , 2024. 

- [61] Riran Cheng, Nan Sang, Yinyuan Zhou, and Xupeng Wang. Universal adversarial attack against 3d object tracking. In _HPCC_ , 2021. 

- [62] Riran Cheng, Xupeng Wang, Ferdous Sohel, and Hang Lei. Black-box explainability-guided adversarial attack for 3d object tracking. _IEEE Transactions on Circuits and Systems for Video Technology (TCSVT)_ , 2025. 

- [63] Zhiyuan Cheng, James Liang, Hongjun Choi, Guanhong Tao, Zhiwen Cao, Dongfang Liu, and Xiangyu Zhang. Physical attack on monocular depth estimation with optimal adversarial patches. In _ECCV_ , 2022. 

- [64] Minkyoung Cho, Yulong Cao, Zixiang Zhou, and Z Morley Mao. Adopt: Lidar spoofing attack detection based on point-level temporal consistency. _arXiv preprint arXiv:2310.14504_ , 2023. 

- [65] Edward Chou, Florian Tramer, and Giancarlo Pellegrino. Sentinet: Detecting localized universal attacks against deep learning systems. In _SPW_ , 2020. 

- [66] Shushman Choudhury, Jayesh K. Gupta, Mykel J. Kochenderfer, Dorsa Sadigh, and Jeannette Bohg. Dynamic multi-robot task allocation under uncertainty and temporal constraints. _Autonomous Robots_ , 2022. 

- [67] Marco Costanzo, Giuseppe De Maria, and Ciro Natale. Handover control for human-robot and robot-robot collaboration. _Frontiers in Robotics and AI_ , 2021. 

- [68] Erwin Coumans and Yunfei Bai. Pybullet, a python module for physics simulation for games, robotics and machine learning. http://pybullet.org, 2016–2021. 

- [69] Sagar Dasgupta, Abdullah Ahmed, Mizanur Rahman, and Thejesh N Bandi. Unveiling the stealthy threat: Analyzing slow drift gps spoofing attacks for autonomous vehicles in urban environments and enabling the resilience. _arXiv preprint arXiv:2401.01394_ , 2024. 

- [70] Daniel Dauner, Marcel Hallgarten, Tianyu Li, Xinshuo Weng, Zhiyu Huang, Zetong Yang, Hongyang Li, Igor Gilitschenski, Boris Ivanovic, Marco Pavone, et al. Navsim: Data-driven non-reactive autonomous vehicle simulation and benchmarking. In _NeurIPS_ , 2024. 

- [71] Christian Schroeder de Witt. Open challenges in multi-agent security: Towards secure systems of interacting ai. _arXiv preprint arXiv:2505.02077_ , 2025. 

- [72] Zehang Deng, Yongjian Guo, Changzhou Han, Wanlun Ma, Junwu Xiong, Sheng Wen, and Yang Xiang. Ai agents under threat: A survey of key security challenges and future pathways. _ACM Computing Surveys_ , 2025. 

- [73] Wenhao Ding, Baiming Chen, Minjun Xu, and Ding Zhao. Learning to collide: An adaptive safety-critical scenarios generating method. In _IROS_ , 2020. 

- [74] Khoa D. Doan, Yingjie Lao, Peng Yang, and Ping Li. Defending backdoor attacks on vision transformer via patch processing. In _AAAI_ , 2023. 

- [75] Yinpeng Dong, Shouwei Ruan, Hang Su, Caixin Kang, Xingxing Wei, and Jun Zhu. Viewfool: Evaluating the robustness of visual recognition to adversarial viewpoints. In _NeurIPS_ , 2022. 

- [76] Alexey Dosovitskiy, German Ros, Felipe Codevilla, Antonio Lopez, and Vladlen Koltun. Carla: An open urban driving simulator. In _CoRL_ , 2017. 

- [77] Haonan Duan, Yifan Yang, Daheng Li, and Peng Wang. Human–robot object handover: Recent progress and future direction. _Robotics_ , 2024. 

- [78] Siyuan Duan, Ke Zhang, and Xizhao Luo. TRAP: Tail-aware ranking attack for world-model planning. _arXiv preprint arXiv:2605.01950_ , 2026. 

52 

- [79] Aya El-Fatyany. A robust multi-sensor fusion model against adversarial patch attack. _Wireless Networks_ , 2026. 

- [80] AbdelRahman Eldosouky, Aidin Ferdowsi, and Walid Saad. Drones in distress: A game-theoretic countermeasure for protecting uavs against gps spoofing. _IEEE Internet of Things Journal (IoT-J)_ , 2019. 

- [81] Kevin Eykholt, Ivan Evtimov, Earlence Fernandes, Bo Li, Amir Rahmati, Chaowei Xiao, Atul Prakash, Tadayoshi Kohno, and Dawn Song. Robust physical-world attacks on deep learning visual classification. In _CVPR_ , 2018. 

- [82] Gianluca Falco, Mario Nicola, and Emanuela Falletti. A dual antenna gnss spoofing detector based on the dispersion of double difference measurements. In _NAVITEC_ , 2018. 

- [83] Jiping Fan, Zhenpo Wang, and Guoqiang Li. Adversarial attack on trajectory prediction for autonomous vehicles with generative adversarial networks. In _IROS_ , 2024. 

- [84] Xiaoliang Fan, Jiarui Chen, Zhuodong Liu, Ziqi Yang, Peixuan Xu, Ruimin Shen, Junhui Liu, Jianzhong Qi, et al. Position: Embodied AI requires a privacy-utility trade-off. _arXiv preprint arXiv:2605.05017_ , 2026. 

- [85] Hongtao Fang, Ruiyun Wang, Zeyu Ma, and Mingang Chen. Pso-based black-box lane detection adversarial attack. In _AIHCIR_ , 2023. 

- [86] Jinyuan Fang, Yanwen Peng, Xi Zhang, Yingxu Wang, Xinhao Yi, Guibin Zhang, et al. A comprehensive survey of self-evolving AI agents: A new paradigm bridging foundation models and lifelong agentic systems. _arXiv preprint arXiv:2508.07407_ , 2025. 

- [87] Senyu Fei, Siyin Wang, Junhao Shi, Zihao Dai, Jikun Cai, Pengfang Qian, Li Ji, Xinzhe He, Shiduo Zhang, Zhaoye Fei, et al. Libero-plus: In-depth robustness analysis of vision-language-action models. _arXiv preprint arXiv:2510.13626_ , 2025. 

- [88] Shiwei Feng, Guanhong Tao, Siyuan Cheng, Guangyu Shen, Xiangzhe Xu, Yingqi Liu, Kaiyuan Zhang, Shiqing Ma, and Xiangyu Zhang. DECREE: Detecting backdoors in pre-trained encoders. In _CVPR_ , 2023. 

- [89] Shuo Feng, Xintao Yan, Haowei Sun, Yiheng Feng, and Henry X Liu. Intelligent driving intelligence test for autonomous vehicles with naturalistic and adversarial environment. _Nature Communications_ , 2021. 

- [90] Yunhao Feng, Yige Li, Yutao Wu, Yingshui Tan, Yanming Guo, Yifan Ding, Kun Zhai, Xingjun Ma, and Yugang Jiang. Backdooragent: A unified framework for backdoor attacks on llm-based agents. _arXiv preprint arXiv:2601.04566_ , 2026. 

- [91] Ignacio Fernández-Hernandez, Vincent Rĳmen, and Gonzalo Seco-Granados. A navigation message authentication proposal for the galileo open service. _NAVIGATION: Journal of the Institute of Navigation_ , 2016. 

- [92] Davide Ferrari, Andrea Pupa, and Cristian Secchi. Compliant blind handover control for human-robot collaboration. In _IROS_ , 2024. 

- [93] Amelia Fiske, Peter Henningsen, and Alena Buyx. Your robot therapist will see you now: ethical implications of embodied artificial intelligence in psychiatry, psychology, and psychotherapy. _Journal of Medical Internet Research (JMIR)_ , 2019. 

- [94] Daniel J Fremont, Edward Kim, Tommaso Dreossi, Shromona Ghosh, Xiangyu Yue, Alberto L SangiovanniVincentelli, and Sanjit A Seshia. Scenic: a language for scenario specification and data generation. _Machine Learning (MLJ)_ , 2023. 

- [95] Masashi Fukunaga and Takeshi Sugawara. Random spoofing attack against lidar-based scan matching slam. In _VehicleSec_ , 2024. 

- [96] Future of Life Institute. 2025 ai safety index. https://futureoflife.org/ai-safety-index-summer-2 025/, 2025. 

- [97] Uri Gadot, Kaixin Wang, Navdeep Kumar, Kfir Yehuda Levy, and Shie Mannor. Bring your own (non-robust) algorithm to solve robust mdps by estimating the worst kernel. In _ICML_ , 2024. 

- [98] Yuyou Gan, Yong Yang, Zhe Ma, Ping He, Rui Zeng, Yiming Wang, Qingming Li, Chunyi Zhou, Songze Li, Ting Wang, et al. Navigating the risks: A survey of security, privacy, and ethics threats in llm-based agents. _arXiv preprint arXiv:2411.09523_ , 2024. 

53 

- [99] Neeraj Gandhi, Yifan Cai, Andreas Haeberlen, and L. T. X. Phan. Roborebound: Multi-robot system defense with bounded-time interaction. In _EuroSys_ , 2025. 

- [100] Ming Gao, Lingfeng Zhang, Leming Shen, Xiang Zou, Jinsong Han, Feng Lin, and Kui Ren. Exploring practical acoustic transduction attacks on inertial sensors in mdof systems. _IEEE Transactions on Mobile Computing_ , 2023. 

- [101] Ruixu Geng, Dongheng Zhang, Yadong Li, Zhi Wu, Jiamu Li, Qi Chen, Yang Hu, and Yan Chen. Attacking mmwave imaging with neural meta-material rendering. _IEEE Transactions on Information Forensics and Security (TIFS)_ , 2025. 

- [102] Tongcheng Geng, Yubin Qu, and W Eric Wong. A white-box prompt injection attack on embodied ai agents driven by large language models. _Journal of Systems and Software_ , 2026. 

- [103] Seyed Kamyar Seyed Ghasemipour, Ayzaan Wahid, Jonathan Tompson, Pannag R. Sanketi, and Igor Mordatch. Self-improving embodied foundation models. _arXiv preprint arXiv:2509.15155_ , 2025. 

- [104] Adam Gleave, Michael Dennis, Cody Wild, Neel Kant, Sergey Levine, and Stuart Russell. Adversarial policies: Attacking deep reinforcement learning. In _ICLR_ , 2020. 

- [105] Tomer Gluck, Moshe Kravchik, Samuel Chocron, Yuval Elovici, and Asaf Shabtai. Spoofing attack on ultrasonic distance sensors using a continuous signal. _Sensors_ , 2020. 

- [106] Chen Gong, Zhou Yang, Yunpeng Bai, Junda He, Jieke Shi, Kecen Li, Arunesh Sinha, Bowen Xu, Xinwen Hou, David Lo, et al. Baffle: Hiding backdoors in offline reinforcement learning datasets. In _S&P_ , 2024. 

- [107] Ido Greenberg, Shie Mannor, Gal Chechik, and Eli A. Meirom. Train hard, fight easy: Robust meta reinforcement learning. In _NeurIPS_ , 2023. 

- [108] Xiangming Gu, Xiaosen Zheng, Tianyu Pang, Chao Du, Qian Liu, Ye Wang, Jing Jiang, and Min Lin. Agent smith: A single image can jailbreak one million multimodal LLM agents exponentially fast. In _ICML_ , 2024. 

- [109] Hanqing Guo, Yuanda Wang, Nikolay Ivanov, Li Xiao, and Qiben Yan. Specpatch: Human-in-the-loop adversarial audio spectrogram patch attack on speech recognition. In _CCS_ , 2022. 

- [110] Junfeng Guo, Ang Li, Lixu Wang, and Cong Liu. Policycleanse: Backdoor detection and mitigation for competitive reinforcement learning. In _ICCV_ , 2023. 

- [111] Weiran Guo, Guanjun Liu, Ziyuan Zhou, and Ling Wang. Pnact: Crafting backdoor attacks in safe reinforcement learning. In _ĲCAI_ , 2025. 

- [112] Wenbo Guo, Xian Wu, Lun Wang, Xinyu Xing, and Dawn Song. _{_ PATROL _}_ : Provable defense against adversarial policy in two-player games. In _USENIX Security_ , 2023. 

- [113] Zhixiang Guo, Siyuan Liang, Andras Balogh, Noah Lunberry, Rong-Cheng Tu, Mark Jelasity, and Dacheng Tao. When world models dream wrong: Physical-conditioned adversarial attacks against world models. _arXiv preprint arXiv:2602.18739_ , 2026. 

- [114] Danna Gurari, Qing Li, Abigale J Stangl, Anhong Guo, Chi Lin, Kristen Grauman, Jiebo Luo, and Jeffrey P Bigham. Vizwiz grand challenge: Answering visual questions from blind people. In _CVPR_ , 2018. 

- [115] Ahmad Hafez, Alireza Naderi Akhormeh, Amr Hegazy, and Amr Alanwar. Safe llm-controlled robots with formal guarantees via reachability analysis. _arXiv preprint arXiv:2503.03911_ , 2025. 

- [116] Martin Hahner, Christos Sakaridis, Dengxin Dai, and Luc Van Gool. Fog simulation on real lidar point clouds for 3d object detection in adverse weather. In _CVPR_ , 2021. 

- [117] R. S. Hallyburton, Yupei Liu, Yulong Cao, Z. Mao, and Miroslav Pajic. Security analysis of camera-lidar fusion against black-box attacks on autonomous vehicles. In _USENIX Security_ , 2022. 

- [118] Xingshuo Han, Guowen Xu, Yuan Zhou, Xuehuan Yang, Jiwei Li, and Tianwei Zhang. Physical backdoor attacks to lane detection systems in autonomous driving. In _MM_ , 2022. 

- [119] Asher James Hancock, Allen Z Ren, and Anirudha Majumdar. Run-time observation interventions make visionlanguage-action models more visually robust. In _ICRA_ , 2025. 

- [120] Niklas Hanselmann, Katrin Renz, Kashyap Chitta, Apratim Bhattacharyya, and Andreas Geiger. King: Generating safety-critical driving scenarios for robust imitation via kinematics gradients. In _ECCV_ , 2022. 

54 

- [121] Adam Haskard and Damith Herath. Secure robotics: Navigating challenges at the nexus of safety, trust, and cybersecurity in cyber-physical systems. _ACM Computing Surveys_ , 2025. 

- [122] Zhongyuan Hau, Kenneth T Co, Soteris Demetriou, and Emil C Lupu. Object removal attacks on lidar-based 3d object detectors. _arXiv preprint arXiv:2102.03722_ , 2021. 

- [123] Zhongyuan Hau, Soteris Demetriou, Luis Muñoz-González, and Emil C. Lupu. Shadow-catcher: Looking into shadows to detect ghost objects in autonomous vehicle 3d sensing. In _ESORICS_ , 2021. 

- [124] Pengfei He, Yuping Lin, Shen Dong, Han Xu, Yue Xing, and Hui Liu. Red-teaming llm multi-agent systems via communication attacks. In _ACL_ , 2025. 

- [125] Robin Heinzler, Florian Piewak, Philipp Schindler, and Wilhelm Stork. Cnn-based lidar point cloud de-noising in adverse weather. _IEEE Robotics and Automation Letters (RA-L)_ , 2020. 

- [126] Jane Holland, Liz Kingston, Conor McCarthy, Eddie Armstrong, Peter O’Dwyer, Fionn Merz, and Mark McConnell. Service robots in the healthcare sector. _Robotics_ , 2021. 

- [127] Zhen Hong, Xiong Li, Zhenyu Wen, Leiqiang Zhou, Huan Chen, and Jie Su. Esp spoofing: Covert acoustic attack on mems gyroscopes in vehicles. _IEEE Transactions on Information Forensics and Security (TIFS)_ , 2022. 

- [128] Eric Horton and Prakash Ranganathan. Development of a gps spoofing apparatus to attack a dji matrice 100 quadcopter. _The Journal of Global Positioning Systems_ , 2018. 

- [129] András Horváth and Csaba M Józsa. Targeted adversarial attacks on generalizable neural radiance fields. In _ICCV_ , 2023. 

- [130] Songqiao Hu, Zeyi Liu, Shuang Liu, Jun Cen, Zihan Meng, and Xiao He. Vlsa: Vision-language-action models with plug-and-play safety constraint layer. _arXiv preprint arXiv:2512.11891_ , 2025. 

- [131] Yuepeng Hu, Yuqi Jia, Mengyuan Li, Dawn Song, and Neil Gong. MalTool: Malicious tool attacks on LLM agents. _arXiv preprint arXiv:2602.12194_ , 2026. 

- [132] Yuyang Hu, Shichun Liu, Yanwei Yue, Guibin Zhang, Boyang Liu, et al. Memory in the age of AI agents. _arXiv preprint arXiv:2512.13564_ , 2025. 

- [133] Ziou Hu, Xiangtong Yao, Yuan Meng, Zhenshan Bing, and Alois Knoll. Dreaming the unseen: World modelregularized diffusion policy for out-of-distribution robustness. _arXiv preprint arXiv:2603.21017_ , 2026. 

- [134] Jeffrey Huang, Ho Jin Choi, and Nadia Figueroa. Trade-off between robustness and rewards adversarial training for deep reinforcement learning. _IEEE Robotics and Automation Letters (RA-L)_ , 2023. 

- [135] Peide Huang, Mengdi Xu, Fei Fang, and Ding Zhao. Robust reinforcement learning as a stackelberg game via adaptively-regularized adversarial training. In _ĲCAI_ , 2022. 

- [136] Qiusheng Huang, Chen Gu, Yaofei Wang, and Donghui Hu. Spotattack: Covering spots on surface to attack lidar based autonomous driving systems. _IEEE Internet of Things Journal (IoT-J)_ , 2024. 

- [137] Shih-Chia Huang, Trung-Hieu Le, and Da-Wei Jaw. Dsnet: Joint semantic learning for object detection in inclement weather conditions. _IEEE Transactions on Pattern Analysis and Machine Intelligence (TPAMI)_ , 2020. 

- [138] Weidong Huang, Jiaming Ji, Borong An, Yueqi Zhang, and Yaodong Yang. Safedreamer: Safe reinforcement learning with world models. In _ICLR_ , 2024. 

- [139] Xinyu Huang, V B ShyamKarthick, Taozhao Chen, Mitch Bryson, Thomas Chaffey, Huaming Chen, Kim-Kwang Raymond Choo, and Ian R. Manchester. Trust in LLM-controlled robotics: A survey of security threats, defenses and challenges. _arXiv preprint arXiv:2601.02377_ , 2026. 

- [140] Yiyang Huang, Zixuan Wang, Zishen Wan, Yapeng Tian, Haobo Xu, Yinhe Han, and Yiming Gan. Annie: Be careful of your robots. _arXiv preprint arXiv:2509.03383_ , 2025. 

- [141] Yuting Huang, Leilei Ding, Zhipeng Tang, Tianfu Wang, Xinrui Lin, Wuyang Zhang, Mingxiao Ma, and Yanyong Zhang. A framework for benchmarking and aligning task-planning safety in llm-based embodied agents. _arXiv preprint arXiv:2504.14650_ , 2025. 

55 

- [142] Muhammad Haris Ikram, Saran Khaliq, Muhammad Latif Anjum, and Wajahat Hussain. Perceptual aliasing++: Adversarial attack for visual slam front-end and back-end. _IEEE Robotics and Automation Letters (RA-L)_ , 2022. 

- [143] Asif Iqbal, Muhammad Naveed Aman, and Biplab Sikdar. A deep learning based induced gnss spoof detection framework. _Machine Learning (MLJ)_ , 2024. 

- [144] Ali Iranmanesh and Peng Liu. Not what you asked for: Typographic attacks in household robot manipulation. _arXiv preprint arXiv:2605.18593_ , 2026. 

- [145] Chashi Mahiul Islam, Shaeke Salman, Montasir Shams, Xiuwen Liu, and Piyush Kumar. Malicious path manipulations via exploitation of representation vulnerabilities of vision-language navigation systems. In _IROS_ , 2024. 

- [146] Saiful Islam, Mohammad Zahidul H Bhuiyan, Sarang Thombre, and Sanna Kaasalainen. Combating singlefrequency jamming through a multi-frequency, multi-constellation software receiver: a case study for maritime navigation in the gulf of finland. _Sensors_ , 2022. 

- [147] Joon-Ha Jang, Mangi Cho, Jaehoon Kim, Dongkwan Kim, and Yongdae Kim. Paralyzing drones via emi signal injection on sensory communication channels. In _NDSS_ , 2023. 

- [148] K. Jansen, Matthias Schäfer, Daniel Moser, Vincent Lenders, Christina Pöpper, and J. Schmitt. Crowd-gps-sec: Leveraging crowdsourcing to detect and localize gps spoofing attacks. In _S&P_ , 2018. 

- [149] Jinseob Jeong, Dongkwan Kim, Joon-Ha Jang, Juhwan Noh, Changhun Song, and Yongdae Kim. Un-rocking drones: Foundations of acoustic injection attacks and recovery thereof. In _NDSS_ , 2023. 

- [150] Xiaoyu Ji, Qinhong Jiang, Chaohao Li, Zhuoyang Shi, and Wenyuan Xu. Watch your speed: Injecting malicious voice commands via time-scale modification. _IEEE Transactions on Information Forensics and Security (TIFS)_ , 2024. 

- [151] Jinyuan Jia, Yupei Liu, and Neil Zhenqiang Gong. BadEncoder: Backdoor attacks to pre-trained encoders in self-supervised learning. In _S&P_ , 2022. 

- [152] Mengjie Jia, Yanyan Li, and Jiawei Yuan. A robust uav tracking solution in the adversarial environment. In _ICTAI_ , 2024. 

- [153] Shuai Jia, Chao Ma, Yibing Song, and Xiaokang Yang. Robust tracking against adversarial attacks. In _ECCV_ , 2020. 

- [154] Xiaojun Jia, Jie Liao, Simeng Qin, Jindong Gu, Wenqi Ren, Xiaochun Cao, Yang Liu, and Philip Torr. Skillject: Effectively automating skill-based prompt injection for skill-enabled agents. _arXiv preprint arXiv:2602.14211_ , 2026. 

- [155] Xiaosong Jia, Zhenjie Yang, Qifeng Li, Zhiyuan Zhang, and Junchi Yan. Bench2drive: Towards multi-ability benchmarking of closed-loop end-to-end autonomous driving. In _NeurIPS_ , 2024. 

- [156] Yunhan Jia Jia, Yantao Lu, Junjie Shen, Qi Alfred Chen, Hao Chen, Zhenyu Zhong, and Tao Wei Wei. Fooling detection alone is not enough: Adversarial attack against multiple object tracking. In _ICLR_ , 2020. 

- [157] Peng Jiang, Hongyi Wu, and Chunsheng Xin. Deeppose: Detecting gps spoofing attack via deep recurrent neural network. _Digital Communications and Networks_ , 2022. 

- [158] Yanna Jiang, Delong Li, Haiyu Deng, Baihe Ma, Xu Wang, Qin Wang, and Guangsheng Yu. SoK: Agentic skills – beyond tool use in LLM agents. _arXiv preprint arXiv:2602.20867_ , 2026. 

- [159] Yuankun Jiang, Chenglin Li, Wenrui Dai, Junni Zou, and Hongkai Xiong. Monotonic robust policy optimization with model discrepancy. In _ICML_ , 2021. 

- [160] Ruochen Jiao, Shaoyuan Xie, Justin Yue, Takami Sato, Lixu Wang, Yixuan Wang, Qi Alfred Chen, and Qi Zhu. Can we trust embodied agents? exploring backdoor attacks against embodied llm-based decision-making systems. _arXiv preprint arXiv:2405.20774_ , 2024. 

- [161] Chang Jin, An Wang, Zeming Wei, Kai Wang, Biaojie Zeng, Qiaosheng Zhang, Chao Yang, Jingjing Qu, Xia Hu, and Xingcheng Xu. SkillSafetyBench: Evaluating agent safety under skill-facing attack surfaces. _arXiv preprint arXiv:2605.12015_ , 2026. 

56 

- [162] Ruimin Jin, Junkun Yan, Xiang Cui, Huiyun Yang, Weimin Zhen, Mingyue Gu, Guangwang Ji, Longjiang Chen, and Haiying Li. A spoofing detection and direction-finding approach for global navigation satellite system signals using off-the-shelf anti-jamming antennas. _Remote Sensing_ , 2025. 

- [163] E. Jones, Alexander Robey, Andy Zou, Zachary Ravichandran, George Pappas, Hamed Hassani, Matt Fredrikson, and J. Kolter. Adversarial attacks on robotic vision language action models. _arXiv preprint arXiv:2506.03350_ , 2025. 

- [164] Eliot Krzysztof Jones, Alexander Robey, Andy Zou, Zachary Ravichandran, George J Pappas, Hamed Hassani, Matt Fredrikson, and J Zico Kolter. Adversarial attacks on robotic vision language action models. _arXiv preprint arXiv:2506.03350_ , 2025. 

- [165] Athira KA and Umashankar Subramaniam. A systematic literature review on multi-robot task allocation. _ACM Computing Surveys_ , 2024. 

- [166] M Shamim Kaiser, Shamim Al Mamun, Mufti Mahmud, and Marzia Hoque Tania. Healthcare robots to combat covid-19. In _COVID-19_ . 2020. 

- [167] Josh Kalin, David Noever, Matt Ciolino, Dominick Hambrick, and Gerry Dozier. Automating defense against adversarial attacks: discovery of vulnerabilities and application of multi-int imagery to protect deployed models. In _Disruptive Tech Info Sci_ , 2021. 

- [168] Akansha Kalra, Basavasagar Patil, Guanhong Tao, and Daniel S. Brown. How vulnerable is my learned policy? universal adversarial perturbation attacks on modern behavior cloning policies. _arXiv preprint arXiv:2502.03698_ , 2025. 

- [169] Sathwik Karnik, Zhang-Wei Hong, Nishant Abhangi, Yen-Chen Lin, Tsun-Hsuan Wang, Christophe Dupuy, Rahul Gupta, and Pulkit Agrawal. Embodied red teaming for auditing robotic foundation models. _arXiv preprint arXiv:2411.18676_ , 2024. 

- [170] Zahra Rezaei Khavas. A review on trust in human-robot interaction. _arXiv preprint arXiv:2105.10045_ , 2021. 

- [171] Soheil Khodayari, Xuenan Zhang, Bhupendra Acharya, and Giancarlo Pellegrino. Indirect prompt injection in the wild: An empirical study of prevalence, techniques, and objectives. _arXiv preprint arXiv:2604.27202_ , 2026. 

- [172] Velat Kilic, Deepti Hegde, A Brinton Cooper, Vishal M Patel, and Mark Foster. LiDAR light scattering augmentation (LISA): Physics-based simulation of adverse weather conditions for 3D object detection. In _ICASSP_ , 2025. 

- [173] Jaekyum Kim, Jaehyung Choi, Yechol Kim, Junho Koh, Chung Choo Chung, and Jun Won Choi. Robust camera lidar sensor fusion via deep gated information fusion network. In _IV_ , 2018. 

- [174] Juhee Kim, Xiaoyuan Liu, Zhun Wang, Shi Qiu, Bo Li, Wenbo Guo, and Dawn Song. The attack and defense landscape of agentic AI: A comprehensive survey. In _USENIX Security_ , 2026. 

- [175] Moo Jin Kim and Karl et al. Pertsch. Openvla: An open-source vision-language-action model. In _CoRL_ , 2025. 

- [176] Ryunosuke Kobayashi, Kazuki Nomoto, Yuna Tanaka, Go Tsuruoka, and Tatsuya Mori. Invisible but detected: Physical adversarial shadow attack and defense on _{_ LiDAR _}_ object detection. In _USENIX Security_ , 2025. 

- [177] Nathan Koenig and Andrew Howard. Design and use paradigms for gazebo, an open-source multi-robot simulator. In _IROS_ , 2004. 

- [178] Rony Komissarov and Avishai Wool. Spoofing attacks against vehicular fmcw radar. In _ASHES_ , 2021. 

- [179] Yufei Kuang, Miao Lu, Jie Wang, Qi Zhou, Bin Li, and Houqiang Li. Learning robust policy against disturbance in transition dynamics via state-conservative policy optimization. In _AAAI_ , 2022. 

- [180] Martin Kuo, Jianyi Zhang, Aolin Ding, Qinsi Wang, Louis DiValentin, Yujia Bao, Wei Wei, Hai Li, and Yiran Chen. H-cot: Hĳacking the chain-of-thought safety reasoning mechanism to jailbreak large reasoning models, including openai o1/o3, deepseek-r1, and gemini 2.0 flash thinking. _arXiv preprint arXiv:2502.12893_ , 2025. 

- [181] Y. Kyrychenko, Ke Zhou, E. Bogucka, and Daniele Quercia. C3ai: Crafting and evaluating constitutions for constitutional ai. In _WWW_ , 2025. 

- [182] Marco Käppler, I. Mamaev, Hosam Alagi, T. Stein, and B. Deml. Optimizing human-robot handovers: The impact of adaptive transport methods. _Robotics_ , 2023. 

57 

- [183] Sahaya Jestus Lazer, Kshitiz Aryal, Maanak Gupta, and Elisa Bertino. A survey of agentic AI and cybersecurity: Challenges, opportunities and use-case prototypes. _arXiv preprint arXiv:2601.05293_ , 2026. 

- [184] Haejoon Lee and Dimitra Panagou. Distributed resilience-aware control in multi-robot networks. In _CDC_ , 2025. 

- [185] Xian Yeow Lee, Sambit Ghadai, Kai Liang Tan, Chinmay Hegde, and Soumik Sarkar. Spatiotemporally constrained action space attacks on deep reinforcement learning agents. In _AAAI_ , 2020. 

- [186] Alexander Lehner, Stefano Gasperini, Alvaro Marcos-Ramiro, Michael Schmidt, Mohammad-Ali Nikouei Mahani, Nassir Navab, Benjamin Busam, and Federico Tombari. 3d-vfield: Adversarial augmentation of point clouds for domain generalization in 3d object detection. In _CVPR_ , 2022. 

- [187] Malte Lenhart, Marco Spanghero, and Panagiotis Papadimitratos. Relay/replay attacks on gnss signals. In _WiSec_ , 2021. 

- [188] Edouard Leurent. An Environment for Autonomous Driving Decision-Making, 2018. 

- [189] Boyi Li, Xiulian Peng, Zhangyang Wang, Jizheng Xu, and Dan Feng. Aod-net: All-in-one dehazing network. In _ICCV_ , 2017. 

- [190] Chaobo Li, Hongjun Li, and Guoan Zhang. Detecting adversarial attacks based on tracking differences in frequency bands. _IEEE Transactions on Multimedia (TMM)_ , 2025. 

- [191] Chengshu Li, Fei Xia, Roberto Martín-Martín, Michael Lingelbach, Sanjana Srivastava, Bokui Shen, Kent Elliott Vainio, Cem Gokmen, Gokul Dharan, Tanish Jain, Andrey Kurenkov, Karen Liu, Hyowon Gweon, Jiajun Wu, Li Fei-Fei, and Silvio Savarese. igibson 2.0: Object-centric simulation for robot learning of everyday household tasks. In _CoRL_ , 2022. 

- [192] Chengyang Li, Heng Zhou, Yang Liu, Caidong Yang, Yongqiang Xie, Zhongbo Li, and Liping Zhu. Detectionfriendly dehazing: Object detection in real-world hazy scenes. _IEEE Transactions on Pattern Analysis and Machine Intelligence (TPAMI)_ , 2023. 

- [193] Jiani Li, Waseem Abbas, Muddasir Shabbir, and Xenofon Koutsoukos. Resilient distributed diffusion for multi-robot systems using centerpoint. In _RSS_ , 2020. 

- [194] Jiayu Li, Yunhan Zhao, Xiang Zheng, Zonghuan Xu, Yige Li, Xing guan Ma, and Yu-Gang Jiang. Attackvla: Benchmarking adversarial and backdoor attacks on vision-language-action models. _arXiv preprint arXiv:2511.12149_ , 2025. 

- [195] Jing-Jing Li, Jianfeng He, Chao Shang, Devang Kulshreshtha, Xun Xian, Yi Zhang, Hang Su, Sandesh Swamy, and Yanjun Qi. Stac: When innocent tools form dangerous chains to jailbreak llm agents. _arXiv preprint arXiv:2509.25624_ , 2025. 

- [196] Jingru Li, Wei Ren, and Tianqing Zhu. Seeing no evil: Blinding large vision-language models to safety instructions via adversarial attention hĳacking. _arXiv preprint arXiv:2604.10299_ , 2026. 

- [197] Jinming Li, Yichen Zhu, Zhiyuan Xu, Jindong Gu, Minjie Zhu, Xin Liu, Ning Liu, Yaxin Peng, Feifei Feng, and Jian Tang. Mmro: Are multimodal llms eligible as the brain for in-home robotics? _arXiv preprint arXiv:2406.19693_ , 2024. 

- [198] Junjie Li, Xi Xiao, Yunbei Zhang, Chen Liu, Lin Zhao, Xiaoying Liao, Yingrui Ji, Janet Wang, Jianyang Gu, Yingqiang Ge, Weĳie Xu, Xi Fang, Xiang Xu, Tianchen Zhao, Youngeun Kim, Tianyang Wang, Jihun Hamm, Smita Krishnaswamy, Jun Huan, and Chandan K. Reddy. Agent harness engineering: A survey. _OpenReview preprint_ , 2026. 

- [199] Leheng Li, Qing Lian, and Ying-Cong Chen. Adv3d: Generating 3d adversarial examples for 3d object detection in driving scenarios with nerf. In _IROS_ , 2024. 

- [200] Manling Li, Shiyu Zhao, Qineng Wang, Kangrui Wang, Yu Zhou, Sanjana Srivastava, Cem Gokmen, Tony Lee, Erran Li Li, Ruohan Zhang, et al. Embodied agent interface: Benchmarking llms for embodied decision making. In _NeurIPS_ , 2024. 

- [201] Qi Li, Bo Yin, Weiqi Huang, Ruhao Liu, Bojun Zou, Runpeng Yu, Jingwen Ye, Weihao Yu, and Xinchao Wang. Vision-Language-Action safety: Threats, challenges, evaluations, and mechanisms. _arXiv preprint arXiv:2604.23775_ , 2026. 

58 

- [202] Quanyi Li, Zhenghao Peng, Lan Feng, Qihang Zhang, Zhenghai Xue, and Bolei Zhou. Metadrive: Composing diverse driving scenarios for generalizable reinforcement learning. _IEEE Transactions on Pattern Analysis and Machine Intelligence (TPAMI)_ , 2022. 

- [203] Shuai Li, Yu Wen, and Xu Cheng. Towards dynamic backdoor attacks against lidar semantic segmentation in autonomous driving. In _TrustCom_ , 2023. 

- [204] Shuai Li, Yu Wen, Huiying Wang, and Xu Cheng. Badlidet: A simple backdoor attack against lidar object detection in autonomous driving. In _TrustCom_ , 2023. 

- [205] Simin Li, Ruixiao Xu, Jingqiao Xiu, Yuwei Zheng, Pu Feng, Yuqing Ma, Bo An, Yaodong Yang, and Xianglong Liu. Robust multi-agent reinforcement learning by mutual information regularization. _IEEE Transactions on Neural Networks and Learning Systems (TNNLS)_ , 2025. 

- [206] Xinqing Li, Xin He, Le Zhang, Min Wu, Xiaoli Li, and Yun Liu. A comprehensive survey on world models for embodied AI. _arXiv preprint arXiv:2510.16732_ , 2025. 

- [207] Yifan Li, Yuhang Chen, Anh Dao, Lichi Li, Zhongyi Cai, Zhen Tan, Tianlong Chen, and Yu Kong. Industryeqa: Pushing the frontiers of embodied question answering in industrial scenarios. _arXiv preprint_ , 2024. 

- [208] Yiming Li, Congcong Wen, Felix Juefei-Xu, and Chen Feng. Fooling lidar perception via adversarial trajectory perturbation. In _CVPR_ , 2021. 

- [209] Zhichao Li, Hongshan Yang, Zhibo Wang, Huiyu Xu, Junhong Lai, Yaopeng Wang, Kui Ren, and Chun Chen. On evaluating the robustness of large vision-language models via untargeted modality alignment breaking adversarial attack. In _USENIX Security_ , 2026. 

- [210] Zhiheng Li, Weng Zhimin, and Yuehuan Wang. Multi-view feature discrepancy attack for single object tracking. In _ICASSP_ , 2025. 

- [211] Zhiyu Li, Chenyang Xi, Chunyu Li, Ding Chen, Boyu Chen, Shichao Song, Simin Niu, Hanyu Wang, Jiawei Yang, Chen Tang, Qingchen Yu, Jihao Zhao, Yezhaohui Wang, Peng Liu, Zehao Lin, Pengyuan Wang, Jiahao Huo, Tianyi Chen, Kai Chen, Kehang Li, Zhen Tao, Huayi Lai, Hao Wu, Bo Tang, Zhengren Wang, Zhaoxin Fan, Ningyu Zhang, Linfeng Zhang, Junchi Yan, Mingchuan Yang, Tong Xu, Wei Xu, Huajun Chen, Haofen Wang, Hongkang Yang, Wentao Zhang, Zhi-Qin John Xu, Siheng Chen, and Feiyu Xiong. Memos: A memory os for ai system. _arXiv preprint arXiv:2507.03724_ , 2025. 

- [212] Zhiyuan Li, Jingzheng Wu, Xiang Ling, Xing Cui, and Tianyue Luo. Towards secure agent skills: Architecture, threat taxonomy, and security analysis. _arXiv preprint arXiv:2604.02837_ , 2026. 

- [213] Zhuohang Li, Cong Shi, Yi Xie, Jian Liu, Bo Yuan, and Yingying Chen. Practical adversarial attacks against speaker recognition systems. In _HotMobile_ , 2020. 

- [214] Zhuohang Li, Yi Wu, Jian Liu, Yingying Chen, and Bo Yuan. Advpulse: Universal, synchronization-free, and targeted audio adversarial attacks via subsecond perturbations. In _CCS_ , 2020. 

- [215] Siyuan Liang, Mingli Zhu, Aishan Liu, Baoyuan Wu, Xiaochun Cao, and Ee-Chien Chang. BadCLIP: Dualembedding guided backdoor attack on multimodal contrastive learning. In _CVPR_ , 2024. 

- [216] Yongyuan Liang, Yanchao Sun, Ruĳie Zheng, and Furong Huang. Efficient adversarial training without attacking: Worst-case-aware robust reinforcement learning. In _NeurIPS_ , 2022. 

- [217] Yongyuan Liang, Yanchao Sun, Ruĳie Zheng, Xiangyu Liu, Benjamin Eysenbach, Tuomas Sandholm, Furong Huang, and Stephen Marcus McAleer. Game-theoretic robust reinforcement learning handles temporally-coupled perturbations. In _ICLR_ , 2024. 

- [218] Yifan Liao, Yuxin Cao, Yedi Zhang, Wentao He, Yan Xiao, Xianglong Du, Zhiyong Huang, and Jin Song Dong. Towards stealthy and effective backdoor attacks on lane detection: A naturalistic data poisoning approach. _arXiv preprint arXiv:2508.15778_ , 2025. 

- [219] Yun-Hsuan Lien, Ping-Chun Hsieh, and Yu-Shuen Wang. Revisiting domain randomization via relaxed stateadversarial policy optimization. In _ICML_ , 2023. 

59 

- [220] Bing Shun Lim, Sye Loong Keoh, and Vrizlynn LL Thing. Autonomous vehicle ultrasonic sensor vulnerability and impact assessment. In _WF-IoT_ , 2018. 

- [221] Aishan Liu, Tairan Huang, Xianglong Liu, Yitao Xu, Yuqing Ma, Xinyun Chen, S. Maybank, and D. Tao. Spatiotemporal attacks for embodied agents. In _ECCV_ , 2020. 

- [222] Aishan Liu, Yuguang Zhou, Xianglong Liu, Tianyuan Zhang, Siyuan Liang, Jiakai Wang, Yanjun Pu, Tianlin Li, Junqi Zhang, Wenbo Zhou, et al. Compromising embodied agents with contextual backdoor attacks. _arXiv preprint arXiv:2408.02882_ , 2024. 

- [223] Chengzhi Liu, Yichen Guo, Yepeng Liu, Yuzhe Yang, Qianqi Yan, Xuandong Zhao, Wenyue Hua, Sheng Liu, Sharon Li, Yuheng Bu, and Xin Eric Wang. Auditing agent harness safety. _arXiv preprint arXiv:2605.14271_ , 2026. 

- [224] Guangyi Liu, Wen Jiang, Boshu Lei, Vivek Pandey, Kostas Daniilidis, and Nader Motee. Beyond uncertainty: Risk-aware active view acquisition for safe robot navigation and 3d scene understanding with fisherrf. _arXiv preprint arXiv:2403.11396_ , 2024. 

- [225] Han Liu, Yuhao Wu, Zhiyuan Yu, Yevgeniy Vorobeychik, and Ning Zhang. Slowlidar: Increasing the latency of lidar-based detection using adversarial examples. In _CVPR_ , 2023. 

- [226] Hanqing Liu, Songping Wang, Jiahuan Long, Jiacheng Hou, Jialiang Sun, Chao Li, Yang Yang, Wei Peng, et al. JailWAM: Jailbreaking world action models in robot control. _arXiv preprint arXiv:2604.05498_ , 2026. 

- [227] Hongbin Liu, Jinyuan Jia, and Neil Zhenqiang Gong. Pointguard: Provably robust 3d point cloud classification. In _CVPR_ , 2021. 

- [228] Jiadong Liu and Tatsuya Mori. Avatar: Adversarial vehicle trajectory attack targeting autonomous driving planner. In _EuroS&PW_ , 2025. 

- [229] Jiani Liu, Yixin He, Lanlan Fan, Qidi Zhong, Yushi Cheng, Meng Zhang, Yanjiao Chen, and Wenyuan Xu. Pina: Prompt injection attack against navigation agents. _arXiv preprint arXiv:2601.13612_ , 2026. 

- [230] Jinbo Liu, Defu Cao, Yifei Wei, Tianyao Su, Yuan Liang, Yushun Dong, Yan Liu, Yue Zhao, and Xiyang Hu. Topology matters: Measuring memory leakage in multi-agent LLMs. _arXiv preprint arXiv:2512.04668_ , 2025. 

- [231] Shuyuan Liu, Jiawei Chen, Shouwei Ruan, Hang Su, and Zhaoxia Yin. Exploring the robustness of decision-level through adversarial attacks on llm-based embodied models. In _MM_ , 2024. 

- [232] Tao Liu, Zhen Hong, and Huan Chen. A traceability localization method of acoustic attack source for mems gyroscope. _IEEE Embedded Systems Letters_ , 2022. 

- [233] Wenjie Liu and Panos Papadimitratos. Gnss spoofing detection based on opportunistic position information. _arXiv preprint arXiv:2506.12580_ , 2025. 

- [234] Wenyu Liu, Gaofeng Ren, Runsheng Yu, Shi Guo, Jianke Zhu, and Lei Zhang. Image-adaptive yolo for object detection in adverse weather conditions. In _AAAI_ , 2022. 

- [235] Xiangyu Liu, Souradip Chakraborty, Yanchao Sun, and Furong Huang. Rethinking adversarial policies: A generalized attack formulation and provable defense in rl. In _ICLR_ , 2024. 

- [236] Xiangyu Liu, Chenghao Deng, Yanchao Sun, Yongyuan Liang, and Furong Huang. Beyond worst-case attacks: Robust rl with adaptive defense via non-dominated policies. In _ICLR_ , 2024. 

- [237] Xiaoqiong Liu, Yuewei Lin, Qing Yang, and Heng Fan. Transferable adversarial attack on 3d object tracking in point cloud. In _MMM_ , 2023. 

- [238] Yi Liu, Weizhe Wang, Ruitao Feng, Yao Zhang, Guangquan Xu, Gelei Deng, Yuekang Li, and Leo Zhang. Agent skills in the wild: An empirical study of security vulnerabilities at scale. _arXiv preprint arXiv:2601.10338_ , 2026. 

- [239] Zhaoyi Liu and Huan Zhang. Stealthy backdoor attack in self-supervised learning vision encoders for large vision language models. In _CVPR_ , 2025. 

- [240] Zhe Liu, Zonghao Ying, Wenxin Zhang, Quanchen Zou, Deyue Zhang, Dongdong Yang, Xiangzheng Zhang, and Hao Peng. SafeHarbor: Hierarchical memory-augmented guardrail for LLM agent safety. _arXiv preprint arXiv:2605.05704_ , 2026. 

60 

- [241] Pablo Alvarez Lopez, Michael Behrisch, Laura Bieker-Walz, Jakob Erdmann, Yun-Pang Flötteröd, Robert Hilbrich, Leonhard Lücken, Johannes Rummel, Peter Wagner, and Evamarie Wießner. Microscopic traffic simulation using sumo. In _ITSC_ , 2018. 

- [242] Alvaro Lopez Pellicer, Plamen Angelov, and Neeraj Suri. Securing (vision-based) autonomous systems: taxonomy, challenges, and defense mechanisms against adversarial threats. _Artificial Intelligence Review_ , 2025. 

- [243] Jianzhi Lou, Qiben Yan, Qing Hui, and Huacheng Zeng. Soundfence: Securing ultrasonic sensors in vehicles using physical-layer defense. In _SECON_ , 2021. 

- [244] Yang Lou, Yi Zhu, Qun Song, Rui Tan, Chunming Qiao, Wei-Bin Lee, and Jianping Wang. A first physical-world trajectory prediction attack via lidar-induced deceptions in autonomous driving. In _USENIX Security_ , 2024. 

- [245] Giulio Lovisotto, Henry Turner, Ivo Sluganovic, Martin Strohmeier, and Ivan Martinovic. Slap: Improving physical adversarial examples with short-lived adversarial perturbations. In _USENIX Security_ , 2021. 

- [246] Hui Lu, Yi Yu, Yiming Yang, Chenyu Yi, Qixin Zhang, Bingquan Shen, A. Kot, and Xudong Jiang. When robots obey the patch: Universal transferable patch attacks on vision-language-action models. _arXiv preprint arXiv:2511.21192_ , 2025. 

- [247] Jiahao Lu, Yifan Zhang, Qiuhong Shen, Xinchao Wang, and Shuicheng Yan. Poison-splat: Computation cost attack on 3d gaussian splatting. _arXiv preprint arXiv:2410.08190_ , 2024. 

- [248] Xiaoya Lu, Yĳin Zhou, Zeren Chen, Ruocheng Wang, Bingrui Sima, Enshen Zhou, Lu Sheng, Dongrui Liu, and Jing Shao. HomeGuard: VLM-based embodied safeguard for identifying contextual risk in household task. _arXiv preprint arXiv:2603.14367_ , 2026. 

- [249] Xuancun Lu, Zhengxian Huang, Xinfeng Li, Chi Zhang, Wenyuan Xu, et al. Poex: Towards policy executable jailbreak attacks against the llm-based robots. _arXiv preprint arXiv:2412.16633_ , 2024. 

- [250] Jinghao Luo, Yuchen Tian, Chuxue Cao, Zeping Luo, Hao Lin, Kai Li, Chengkai Kong, Ruiming Yang, and Jing Ma. From storage to experience: A survey on the evolution of LLM agent memory mechanisms. _Preprints.org_ , 2026. 

- [251] Kaiwen Luo, Zhenhong Zhou, Leo Wang, Liang Lin, Yang Xiao, Tianyu Shao, Yuanhe Zhang, Yuxuan Li, Miao Yu, Kailin Lyu, Jiaming Zhang, Dongrui Liu, Li Sun, Yueming Wu, Kai Li, Ting Dang, Xiaojun Jia, Rohan Kumar Das, Xinfeng Li, Siyuan Liang, Qiufeng Wang, Xingjun Ma, Jing Chen, Kun Wang, Junhao Dong, Deqing Zou, Yu Cheng, Xia Hu, Zhigang Zeng, Sen Su, Yang Liu, Yu-Gang Jiang, Philip S. Yu, and Yew-Soon Ong. A survey of large audio language models: Generalization, trustworthiness, and outlook. _arXiv preprint arXiv:2605.20266_ , 2026. 

- [252] Tung M. Luu, Thanh Nguyen, Tee Joshua Tian Jin, Sungwoon Kim, and Chang D. Yoo. Mitigating adversarial perturbations for deep reinforcement learning via vector quantization. In _IROS_ , 2024. 

- [253] Lĳia Lv, Xuehai Tang, Jie Wen, Jizhong Han, and Songlin Hu. Structured security auditing and robustness enhancement for untrusted agent skills. _arXiv preprint arXiv:2604.25109_ , 2026. 

- [254] Wenqi Lyu, Zerui Li, Yanyuan Qiao, and Qi Wu. Badnaver: Exploring jailbreak attacks on vision-and-language navigation. _arXiv preprint arXiv:2505.12443_ , 2025. 

- [255] Boyang Ma, Hechuan Guo, Peizhuo Lv, Minghui Xu, Xuelong Dai, YeChao Zhang, Yĳun Yang, and Yue Zhang. What breaks embodied AI security: LLM vulnerabilities, CPS flaws, or something else? _arXiv preprint arXiv:2602.17345_ , 2026. 

- [256] Chen Ma, Ningfei Wang, Qi Alfred Chen, and Chao Shen. Wip: Towards the practicality of the adversarial attack on object tracking in autonomous driving. In _VehicleSec_ , 2023. 

- [257] Chen Ma, Ningfei Wang, Zhengyu Zhao, Qian Wang, Qi Alfred Chen, and Chao Shen. Controlloc: Physical-world hĳacking attack on visual perception in autonomous driving. _arXiv preprint arXiv:2406.05810_ , 2024. 

- [258] Oubo Ma, Yuwen Pu, Linkang Du, Yang Dai, Ruo Wang, Xiaolei Liu, Yingcai Wu, and Shouling Ji. Sub-play: Adversarial policies against partially observed multi-agent reinforcement learning systems. In _CCS_ , 2024. 

- [259] Xiaojian Ma, Silong Yong, Zilong Zheng, Qing Li, Yitao Liang, Song-Chun Zhu, and Siyuan Huang. Sqa3d: Situated question answering in 3d scenes. In _ICLR_ , 2023. 

61 

- [260] Xingjun Ma, Yifeng Gao, Yixu Wang, Ruofan Wang, Xin Wang, Ye Sun, Yifan Ding, Hengyuan Xu, Yunhao Chen, Yunhao Zhao, et al. Safety at scale: A comprehensive survey of large model and agent safety. _Foundations and Trends®_ , 2025. 

- [261] Xingjun Ma, Yixu Wang, Hengyuan Xu, Yutao Wu, Yifan Ding, Yunhan Zhao, Zilong Wang, Jiabin Hua, Ming Wen, Jianan Liu, Ranjie Duan, Yifeng Gao, Yingshui Tan, Yunhao Chen, Hui Xue, Xin Wang, Wei Cheng, Jingjing Chen, Zuxuan Wu, Bo Li, and Yu-Gang Jiang. A safety report on GPT-5.2, Gemini 3 pro, Qwen3-VL, Grok 4.1 fast, nano banana pro, and seedream 4.5. _arXiv preprint arXiv:2601.10527_ , 2026. 

- [262] Yingzi Ma, Yulong Cao, Jiachen Sun, Marco Pavone, and Chaowei Xiao. Dolphins: Multimodal language model for driving. In _ECCV_ , 2024. 

- [263] Kira Maag and Asja Fischer. Uncertainty-weighted loss functions for improved adversarial attacks on semantic segmentation. In _WACV_ , 2024. 

- [264] KT Yasas Mahima, Asanka G Perera, Sreenatha Anavatti, and Matt Garratt. Toward robust 3d perception for autonomous vehicles: A review of adversarial attacks and countermeasures. _IEEE Transactions on Intelligent Transportation Systems_ , 2024. 

- [265] Ajay Mandlekar, Yuke Zhu, Animesh Garg, Li Fei-Fei, and Silvio Savarese. Adversarially robust policy learning through active construction of physically-plausible perturbations. In _IROS_ , 2017. 

- [266] Chengzhi Mao, Scott Geng, Junfeng Yang, Xin Wang, and Carl Vondrick. Understanding zero-shot adversarial robustness for large-scale models. In _ICLR_ , 2023. 

- [267] Junyuan Mao, Fanci Meng, Yifan Duan, Miao Yu, Xiaojun Jia, Junfeng Fang, Yuxuan Liang, Kun Wang, and Qingsong Wen. Agentsafe: Safeguarding large language model-based multi-agent systems via hierarchical data management. _arXiv preprint arXiv:2503.04392_ , 2025. 

- [268] Francesco Marchiori, Rohan Sinha, Christopher Agia, Alexander Robey, George J Pappas, Mauro Conti, and Marco Pavone. Preventing robotic jailbreaking via multimodal domain adaptation. _arXiv preprint arXiv:2509.23281_ , 2025. 

- [269] Marco Melis, Ambra Demontis, Battista Biggio, Gavin Brown, Giorgio Fumera, and Fabio Roli. Is deep learning safe for robot vision? adversarial examples against the icub humanoid. In _ICCV_ , 2017. 

- [270] Chongxi Meng, Tianwei Zhang, Da Zhao, and T. Lam. Fast and comfortable robot-to-human handover for mobile cooperation robot system. _Cyborg and Bionic Systems_ , 2024. 

- [271] Dejian Meng, Wei Xiao, Lĳun Zhang, Zhuang Zhang, and Zihao Liu. Vehicle trajectory prediction based predictive collision risk assessment for autonomous driving in highway scenarios. _arXiv preprint arXiv:2304.05610_ , 2023. 

- [272] Ibomoiye Domor Mienye, Ebenezer Esenogho, and Cameron Modisane. Deep reinforcement learning in the era of foundation models: A survey. _Computers_ , 2026. 

- [273] Sarthak Mishra, R. Yadav, Avirup Das, Saksham Gupta, Wei Pan, and Spandan Roy. Aermani-vlm: Structured prompting and reasoning for aerial manipulation with vision language models. _arXiv preprint arXiv:2511.01472_ , 2025. 

- [274] Pedram MohajerAnsari, Amir Salarpour, Jan De Voor, Alkim Domeke, Arkajyoti Mitra, Grace Johnson, Habeeb Olufowobi, Mohammad Hamad, and Mert D Pese. Discovering new shadow patterns for black-box attacks on lane detection of autonomous vehicles. _arXiv preprint arXiv:2409.18248_ , 2024. 

- [275] Yao Mu, Junting Chen, Qinglong Zhang, Shoufa Chen, Qiaojun Yu, Chongjian Ge, Runjian Chen, Zhixuan Liang, Mengkang Hu, Chaofan Tao, Peize Sun, Haibao Yu, Chao Yang, Wenqi Shao, Wenhai Wang, Jifeng Dai, Yu Qiao, Mingyu Ding, and Ping Luo. Robocodex. In _ICML_ , 2024. 

- [276] Mohaiminul Al Nahian, Zainab Altaweel, David Reitano, Sabbir Ahmed, Saumitra Lohokare, Shiqi Zhang, and Adnan Siraj Rakin. Robo-troj: Attacking llm-based task planners. _arXiv preprint arXiv:2504.17070_ , 2025. 

- [277] Kosuke Nakanishi, Akihiro Kubo, Yuji Yasui, and Shin Ishii. Off-policy actor-critic for adversarial observation robustness: Virtual alternative training via symmetric policy evaluation. In _ICML_ , 2025. 

- [278] Mahiro Nakao and Kazuhiro Takemoto. Benchmarking the safety of large language models for robotic health attendant control. _arXiv preprint arXiv:2604.26577_ , 2026. 

62 

- [279] Prateek Nallabolu and Changzhi Li. A frequency-domain spoofing attack on fmcw radars and its mitigation technique based on a hybrid-chirp waveform. _IEEE Transactions on Microwave Theory and Techniques (TMTT)_ , 2021. 

- [280] Ben Nassi, Yisroel Mirsky, Dudi Nassi, Raz Ben-Netanel, Oleg Drokin, and Yuval Elovici. Phantom of the adas: Securing advanced driver-assistance systems from split-second phantom attacks. In _CCS_ , 2020. 

- [281] Dudi Nassi, Raz Ben-Netanel, Yuval Elovici, and Ben Nassi. Mobilbye: attacking adas with camera spoofing. _arXiv preprint arXiv:1906.09765_ , 2019. 

- [282] John J. Nay. Aligning ai agents with humans through law as information. Stanford Law School Working Paper, 2025. 

- [283] Subash Neupane, Shaswata Mitra, I. Fernandez, Swayamjit Saha, Sudip Mittal, Jingdao Chen, Nisha Pillai, and Shahram Rahimi. Security considerations in ai-robotics: A survey of current methods, challenges, and opportunities. _IEEE Access_ , 2023. 

- [284] Buqing Nie, Yangqing Fu, Jingtian Ji, and Yue Gao. Action robust reinforcement learning via optimal adversary aware policy optimization, 2025. 

- [285] Yuwei Niu, Shuo He, Qi Wei, Zongyu Wu, Feng Liu, and Lei Feng. BDetCLIP: Multimodal prompting contrastive test-time backdoor detection. In _ICML_ , 2025. 

- [286] Fatemeh Nourilenjan Nokabadi, Yann Batiste Pequignot, and Jean-Francois Lalonde. Trackpgd: Efficient adversarial attack using object binary masks against robust transformer trackers. _arXiv preprint arXiv:2407.03946_ , 2024. 

- [287] NVIDIA. Isaac Sim. 

- [288] Ike Obi, Vishnunandan LN Venkatesh, Weizheng Wang, Ruiqi Wang, Dayoon Suh, Temitope I Amosa, Wonse Jo, and Byung-Cheol Min. Safeplan: Leveraging formal logic and chain-of-thought reasoning for enhanced safety in llm-based robotic task planning. _arXiv preprint arXiv:2503.06892_ , 2025. 

- [289] Tuomas P. Oikarinen, Wang Zhang, Alexandre Megretski, Luca Daniel, and Tsui-Wei Weng. Robust deep reinforcement learning through adversarial loss. In _NeurIPS_ , 2021. 

- [290] OWASP. Cascading failures in agentic ai: Asi08 security guide. https://adversa.ai/blog/owasp-asi02 -tool-misuse-and-exploitation-the-definitive-security-guide/, 2026. 

- [291] OWASP GenAI Security Project. Owasp. https://genai.owasp.org/resource/owasp-top-10-for-a gentic-applications-for-2026/, 2026. 

- [292] Manoj Parmar. Safety, security, and cognitive risks in world models. _arXiv preprint arXiv:2604.01346_ , 2026. 

- [293] Jared Perlo, Alexander Robey, Fazl Barez, Luciano Floridi, and Jakob Mökander. Embodied AI: Emerging risks and opportunities for policy action. _arXiv preprint arXiv:2509.00117_ , 2025. 

- [294] Karl Pertsch, Kyle Stachowicz, Brian Ichter, Danny Driess, Suraj Nair, Quan Vuong, Oier Mees, Chelsea Finn, and Sergey Levine. Fast: Efficient action tokenization for vision-language-action models. _arXiv preprint arXiv:2501.09747_ , 2025. 

- [295] Lerrel Pinto, James Davidson, Rahul Sukthankar, and Abhinav Gupta. Robust adversarial reinforcement learning. In _ICML_ , 2017. 

- [296] Oscar Pozzobon, Luca Canzian, Matteo Danieletto, and Andrea Dalla Chiara. Anti-spoofing and open gnss signal authentication with signal authentication sequences. In _NAVITEC_ , 2010. 

- [297] Xavier Puig, Eric Undersander, Andrew Szot, Mikael Dallaire Cote, Tsung-Yen Yang, Ruslan Partsey, Ruta Desai, Alexander William Clegg, Michal Hlavac, So Yeon Min, et al. Habitat 3.0: A co-habitat for humans, avatars and robots. _arXiv preprint arXiv:2310.13724_ , 2023. 

- [298] Sidharth Pulipaka, Stanislau Hlebik, Leonidas Raghav, Sahar Abdelnabi, Vyas Raina, Ivaxi Sheth, and Mario Fritz. Hidden in memory: Sleeper memory poisoning in LLM agents. _arXiv preprint arXiv:2605.15338_ , 2026. 

- [299] Delin Qu, Haoming Song, Qizhi Chen, Yuanqi Yao, Xinyi Ye, Yan Ding, Zhigang Wang, JiaYuan Gu, Bin Zhao, Dong Wang, et al. Spatialvla: Exploring spatial representations for visual-language-action model. In _RSS_ , 2025. 

63 

- [300] Yansong Qu, Zilin Huang, Zihao Sheng, Jiancong Chen, Yue Leng, Samuel Labi, and Sikai Chen. VLM-SAFE: Vision-language model-guided safety-aware reinforcement learning with world models for autonomous driving. _arXiv preprint arXiv:2505.16377_ , 2025. 

- [301] Yubin Qu, Yi Liu, Tongcheng Geng, Gelei Deng, Yuekang Li, Leo Yu Zhang, Ying Zhang, and Lei Ma. Supply-chain poisoning attacks against LLM coding agent skill ecosystems. _arXiv preprint arXiv:2604.03081_ , 2026. 

- [302] S. Rahman. Biomimetic approach to designing trust-based robot-to-human object handover in a collaborative assembly task. _Robotics_ , 2025. 

- [303] Aravind Rajeswaran, Sarvjeet Ghotra, Balaraman Ravindran, and Sergey Levine. Epopt: Learning robust neural network policies using model ensembles. In _ICLR_ , 2017. 

- [304] Zachary Ravichandran, Alexander Robey, Vĳay Kumar, George J. Pappas, and Hamed Hassani. Safety guardrails for LLM-enabled robots. _IEEE RA-L_ , 2026. 

- [305] Santhosh Kumar Ravindran. Moral anchor system: A predictive framework for ai value alignment and drift prevention. _arXiv preprint arXiv:2510.04073_ , 2025. 

- [306] Davis Rempe, Jonah Philion, Leonidas J Guibas, Sanja Fidler, and Or Litany. Generating useful accident-prone driving scenarios via a learned traffic prior. In _CVPR_ , 2022. 

- [307] Qibing Ren, Sitao Xie, Longxuan Wei, Zhenfei Yin, Junchi Yan, Lizhuang Ma, and Jing Shao. When autonomy goes rogue: Preparing for risks of multi-agent collusion in social systems. _arXiv preprint arXiv:2507.14660_ , 2025. 

- [308] Alexander Robey, Zachary Ravichandran, Vĳay Kumar, Hamed Hassani, and George Pappas. Jailbreaking llm-controlled robots. _arXiv preprint arXiv:2410.13691_ , 2024. 

- [309] Matteo Rubagotti, Inara Tusseyeva, Sara Baltabayeva, Danna Summers, and A. Sandygulova. Perceived safety in physical human robot interaction – a survey. _Robotics and Autonomous Systems_ , 2021. 

- [310] Chudamani Sahu and Shashi Poddar. Acoustic attack mitigation approach for mems inertial sensors using change point detection on mhimu framework. _IEEE Transactions on Aerospace and Electronic Systems_ , 2024. 

- [311] Saeid Samizade, Zheng-Hua Tan, Chao Shen, and Xiaohong Guan. Adversarial example detection by classification for deep speech recognition. In _ICASSP_ , 2020. 

- [312] Hongrui Sang, Rong Jiang, Zhipeng Wang, Yanmin Zhou, Ping Lu, and Bin He. Scene augmentation methods for interactive embodied ai tasks. _IEEE Transactions on Instrumentation and Measurement_ , 2023. 

- [313] Takami Sato, Junjie Shen, Ningfei Wang, Yunhan Jia, Xue Lin, and Qi Alfred Chen. Dirty road can attack: Security of deep learning based automated lane centering under physical-world attack. In _USENIX Security_ , 2021. 

- [314] Christian Schlarmann, Naman Deep Singh, Francesco Croce, and Matthias Hein. Robust CLIP: Unsupervised adversarial fine-tuning of vision embeddings for robust large vision-language models. In _ICML_ , 2024. 

- [315] Jenny Schmalfuss, Philipp Scholze, and Andres Bruhn. A perturbation-constrained adversarial attack for evaluating the robustness of optical flow. In _ECCV_ , 2022. 

- [316] Pierre Sermanet, Anirudha Majumdar, Alex Irpan, Dmitry Kalashnikov, and Vikas Sindhwani. Generating robot constitutions & benchmarks for semantic safety. _arXiv preprint arXiv:2503.08663_ , 2025. 

- [317] Asif Shahriar, Md Nafiu Rahman, Sadif Ahmed, Farig Sadeque, and Md Rizwan Parvez. A survey on agentic security: Applications, threats and defenses. _arXiv preprint arXiv:2510.06445_ , 2025. 

- [318] Md Hasan Shahriar, Md Mohaimin Al Barat, Harshavardhan Sundar, Ning Zhang, Naren Ramakrishnan, Y. T. Hou, and W. Lou. Temporal misalignment attacks against multimodal perception in autonomous driving. _arXiv preprint arXiv:2507.09095_ , 2025. 

- [319] Shuai Shao, Qihan Ren, Chen Qian, Boyi Wei, Dadi Guo, Jingyi Yang, Xinhao Song, Linfeng Zhang, Weinan Zhang, Dongrui Liu, and Jing Shao. Your agent may misevolve: Emergent risks in self-evolving llm. _arXiv preprint arXiv:2509.26354_ , 2025. 

- [320] Junjie Shen, Jun Yeon Won, Zeyuan Chen, and Qi Alfred Chen. Drift with devil: Security of multi-sensor fusion based localization in autonomous driving under gps spoofing. In _USENIX Security_ , 2020. 

64 

- [321] Jiawen Shi, Zenghui Yuan, Guiyao Tie, Pan Zhou, Neil Zhenqiang Gong, and Lichao Sun. Prompt injection attack to tool selection in llm. _arXiv preprint arXiv:2504.19793_ , 2025. 

- [322] Raushan Kumar Singh and Sudeepta Mishra. Securetrack: Protecting vehicular sensors from noninvasive emi attacks. _IEEE Sensors Journal_ , 2025. 

- [323] Chawin Sitawarin, Arjun Nitin Bhagoji, Arsalan Mosenia, Mung Chiang, and Prateek Mittal. Darts: Deceiving autonomous cars with toxic signs. _arXiv preprint arXiv:1802.06430_ , 2018. 

- [324] Yunmok Son, Hocheol Shin, Dongkwan Kim, Youngseok Park, Juhwan Noh, Kibum Choi, Jungwoo Choi, and Yongdae Kim. Rocking drones with intentional sound noise on gyroscopic sensors. In _USENIX Security_ , 2015. 

- [325] Yufei Song, Ziqi Zhou, Minghui Li, Xianlong Wang, Hangtao Zhang, Menghao Deng, Wei Wan, Shengshan Hu, and Leo Yu Zhang. Pb-uap: Hybride universal adversarial attack for image segmentation. In _ICASSP_ , 2025. 

- [326] Marco Spanghero, Filip Geib, Ronny Panier, and Panos Papadimitratos. Gnss jammer localization and identification with airborne commercial gnss receivers. _IEEE Transactions on Information Forensics and Security (TIFS)_ , 2025. 

- [327] Siddharth Srikanth, Freddie Liang, Ya-Chuan Hsu, Varun Bhatt, Shihan Zhao, Henry Chen, Bryon Tjanaka, Minjune Hwang, Akanksha Saran, Daniel Seita, et al. Red-teaming vision-language-action models via quality diversity prompt generation for robust robot policies. _arXiv preprint arXiv:2603.12510_ , 2026. 

- [328] Maxwell Standen, Junae Kim, and Claudia Szabo. Adversarial machine learning attacks and defences in multi-agent reinforcement learning. _ACM Computing Surveys_ , 2024. 

- [329] Jonathan Steinberg and Oren Gal. Semantic denial of service in LLM-controlled robots. _arXiv preprint arXiv:2604.24790_ , 2026. 

- [330] Volker Strobel, Eduardo Castelló Ferrer, and Marco Dorigo. Blockchain technology secures robot swarms: A comparison of consensus protocols and their resilience to byzantine robots. _Robotics_ , 2020. 

- [331] Volker Strobel, Alexandre Pacheco, and Marco Dorigo. Robot swarms neutralize harmful byzantine robots using a blockchain-based token economy. _Science Robotics_ , 2023. 

- [332] Chung-En Sun, Sicun Gao, and Tsui-Wei Weng. Breaking the barrier: Enhanced utility and robustness in smoothed drl agents. In _ICML_ , 2024. 

- [333] Jiachen Sun, Yulong Cao, Christopher B Choy, Zhiding Yu, Anima Anandkumar, Zhuoqing Morley Mao, and Chaowei Xiao. Adversarially robust 3d point cloud recognition using self-supervisions. In _NeurIPS_ , 2021. 

- [334] Jianwen Sun, Tianwei Zhang, Xiaofei Xie, Lei Ma, Yan Zheng, Kangjie Chen, and Yang Liu. Stealthy and efficient adversarial attacks against deep reinforcement learning. In _AAAI_ , 2020. 

- [335] Qi Sun, Ahmed Abdo, Luis Burbano, Ziyang Li, Yaxing Yao, Alvaro Cardenas, and Yinzhi Cao. Beyond crash: Hĳacking your autonomous vehicle for fun and profit. _arXiv preprint arXiv:2602.07249_ , 2026. 

- [336] Ruixiang Sun, Hongyu Zang, Xin Li, and Riashat Islam. Learning latent dynamic robust representations for world models. In _ICML_ , 2024. 

- [337] Yanchao Sun, Ruĳie Zheng, Yongyuan Liang, and Furong Huang. Who is the strongest enemy? towards optimal and efficient evasion attacks in deep rl. In _ICLR_ , 2022. 

- [338] Yanchao Sun, Ruĳie Zheng, Parisa Hassanzadeh, Yongyuan Liang, Soheil Feizi, Sumitra Ganesh, and Furong Huang. Certifiably robust policy learning against adversarial multi-agent communication. In _ICLR_ , 2023. 

- [339] Yitong Sun, Yao Huang, and Xingxing Wei. Embodied laser attack: leveraging scene priors to achieve agent-based robust non-contact attacks. In _MM_ , 2024. 

- [340] Youbang Sun, Xiang Wang, Jie Fu, Chaochao Lu, and Bowen Zhou. R2ai: Towards resistant and resilient ai in an evolving world. _arXiv preprint arXiv:2509.06786_ , 2025. 

- [341] Zhi Sun, Sarankumar Balakrishnan, Lu Su, Arupjyoti Bhuyan, Pu Wang, and Chunming Qiao. Who is in control? practical physical layer attack and defense for mmwave-based sensing in autonomous vehicles. _IEEE Transactions on Information Forensics and Security (TIFS)_ , 2021. 

65 

- [342] Priyanka Surve, A. Shabtai, and Y. Elovici. Sok: Cybersecurity assessment of humanoid ecosystem. _arXiv preprint arXiv:2508.17481_ , 2025. 

- [343] Carolyn J Swinney and John C Woods. Gnss jamming classification via cnn, transfer learning & the novel concatenation of signal representations. In _CyberSA_ , 2021. 

- [344] Adrian Szvoren, Jianwei Liu, Dimitrios Kanoulas, and Nilufer Tuptuk. Exploring adversarial obstacle attacks in search-based path planning for autonomous mobile robots. In _ICRA_ , 2025. 

- [345] Kai Liang Tan, Yasaman Esfandiari, Xian Yeow Lee, and Aakanksha. Robustifying reinforcement learning agents via action space adversarial training. In _ACC_ , 2020. 

- [346] Xin Tan, Bangwei Liu, Yicheng Bao, Qĳian Tian, Zhenkun Gao, Xiongbin Wu, Zhihao Luo, Sen Wang, Yuqi Zhang, Xuhong Wang, et al. Towards safe and trustworthy embodied ai: foundations, status, and prospects. _OpenReview preprint_ , 2025. 

- [347] Xiaohang Tang, Afonso Marques, Parameswaran Kamalaruban, and Ilĳa Bogunovic. Adversarially robust decision transformer. In _NeurIPS_ , 2024. 

- [348] Riya Tapwal, Abhishek Kumar, and Carsten Maple. PRISM: Generation-time detection and mitigation of secret leakage in multi-agent LLM pipelines. _arXiv preprint arXiv:2605.10614_ , 2026. 

- [349] Gemini Robotics Team, Saminda Abeyruwan, Joshua Ainslie, Jean-Baptiste Alayrac, Montserrat Gonzalez Arenas, Travis Armstrong, Ashwin Balakrishna, Robert Baruch, Maria Bauza, Michiel Blokzĳl, et al. Gemini robotics: Bringing ai into the physical world. _arXiv preprint arXiv:2503.20020_ , 2025. 

- [350] Chen Tessler, Yonathan Efroni, and Shie Mannor. Action robust reinforcement learning and applications in continuous control. In _ICML_ , 2019. 

- [351] Kevin Sam Tharayil, Benyamin Farshteindiker, Shaked Eyal, Nir Hasidim, Roy Hershkovitz, Shani Houri, Ilia Yoffe, Michal Oren, and Yossi Oren. Sensor defense in-software (sdi): Practical software based detection of spoofing attacks on position sensors. _Artificial Intelligence (AĲ)_ , 2020. 

- [352] Jakob Thumm, Guillaume Pelat, and Matthias Althoff. Reducing safety interventions in provably safe reinforcement learning. In _IROS_ , 2023. 

- [353] Simen Thys, Wiebe Van Ranst, and Toon Goedemé. Fooling automated surveillance cameras: adversarial patches to attack person detection. In _CVPRW_ , 2019. 

- [354] Shengjing Tian, Xiantong Zhao, Yuhao Bian, Yinan Han, and Bin Liu. Adversarial attacks on lidar-based tracking across road users: Robustness evaluation and target-aware black-box method. _arXiv preprint arXiv:2410.20893_ , 2024. 

- [355] Xiaoyu Tian, Junru Gu, Bailin Li, Yicheng Liu, Yang Wang, Zhiyong Zhao, Kun Zhan, Peng Jia, Xianpeng Lang, and Hang Zhao. Drivevlm: The convergence of autonomous driving and large vision-language models. In _CoRL_ , 2024. 

- [356] Emanuel Todorov, Tom Erez, and Yuval Tassa. Mujoco: A physics engine for model-based control. In _IROS_ , 2012. 

- [357] Timofey Tomashevskiy. Safe continual reinforcement learning methods for nonstationary environments. towards a survey of the state of the art. _arXiv preprint arXiv:2601.05152_ , 2026. 

- [358] Nenad Tomašev, Matĳa Franklin, Julian Jacobs, Sébastien Krier, and Simon Osindero. Distributional agi safety. _arXiv preprint arXiv:2512.16856_ , 2025. 

- [359] Tristan Tomilin, Meng Fang, and Mykola Pechenizkiy. Hasard: A benchmark for vision-based safe reinforcement learning in embodied agents. _arXiv preprint arXiv:2503.08241_ , 2025. 

- [360] Baoshun Tong, Haoran He, Ling Pan, Yang Liu, and Liang Lin. Uncovering linguistic fragility in vision-languageaction models via diversity-aware red teaming. _arXiv preprint arXiv:2604.05595_ , 2026. 

- [361] Mukun Tong, Charles Dawson, and Chuchu Fan. Enforcing safety for vision-based controllers via control barrier functions and neural radiance fields. _arXiv preprint arXiv:2209.12266_ , 2022. 

- [362] Tuan Duong Trinh, Naveed Akhtar, and Basim Azam. Altered thoughts, altered actions: Probing chain-of-thought vulnerabilities in VLA robotic manipulation. _arXiv preprint arXiv:2603.12717_ , 2026. 

66 

- [363] Timothy Trippel, Ofir Weisse, Wenyuan Xu, Peter Honeyman, and Kevin Fu. Walnut: Waging doubt on the integrity of mems accelerometers with acoustic injection attacks. In _EuroS&P_ , 2017. 

- [364] Wei-Cheng Tseng, Jinwei Gu, Qinsheng Zhang, Hanzi Mao, Ming-Yu Liu, Florian Shkurti, and Lin Yen-Chen. Scalable policy evaluation with video world models. _arXiv preprint arXiv:2511.11520_ , 2025. 

- [365] James Tu, Mengye Ren, Sivabalan Manivasagam, Ming Liang, Bin Yang, Richard Du, Frank Cheng, and Raquel Urtasun. Physically realizable adversarial examples for lidar object detection. In _CVPR_ , 2020. 

- [366] Alan M Turing. Computing machinery and intelligence. In _Parsing the Turing test_ . 1950. 

- [367] Tavish Vaidya, Yuankai Zhang, Micah Sherr, and Clay Shields. Cocaine noodles: exploiting the gap between human and machine speech recognition. In _WOOT_ , 2015. 

- [368] Sai Vemprala and Ashish Kapoor. Adversarial attacks on optimization based planners. In _ICRA_ , 2021. 

- [369] Rohith Reddy Vennam, Ish Kumar Jain, Kshitiz Bansal, Joshua Orozco, Puja Shukla, Aanjhan Ranganathan, and Dinesh Bharadia. mmspoof: Resilient spoofing of automotive millimeter-wave radars using reflect array. In _S&P_ , 2023. 

- [370] Eugene Vinitsky, Yuqing Du, Kanaad Parvate, Kathy Jang, Pieter Abbeel, and Alexandre Bayen. Robust reinforcement learning using adversarial populations, 2020. 

- [371] Payton Walker, Tianfang Zhang, Cong Shi, Nitesh Saxena, and Yingying Chen. Barrierbypass: Out-of-sight clean voice command injection attacks through physical barriers. In _WiSec_ , 2023. 

- [372] Bo Wang, Weiyi He, Shenglai Zeng, Zhen Xiang, Yue Xing, Jiliang Tang, and Pengfei He. Unveiling privacy risks in LLM agent memory. In _ACL_ , 2025. 

- [373] Chen Wang, Angtian Wang, Junbo Li, Alan Yuille, and Cihang Xie. Benchmarking robustness in neural radiance fields. In _CVPR_ , 2024. 

- [374] Cheng-Zhen Wang, Ling-Wei Kong, Junjie Jiang, and Ying-Cheng Lai. Machine learning-based approach to gps antĳamming. _GPS Solutions_ , 2021. 

- [375] Chenxu Wang and Huaping Liu. Towards robust deep reinforcement learning against environmental state perturbation, 2025. 

- [376] Chenyi Wang, Yanmao Man, Raymond Muller, Ming Li, Z Berkay Celik, Ryan Gerdes, and Jonathan Petit. Physical id-transfer attacks against multi-object tracking via adversarial trajectory. In _ACSAC_ , 2024. 

- [377] Fei Wang, Hong Li, and Mingquan Lu. Gnss spoofing detection and mitigation based on maximum likelihood estimation. _Sensors_ , 2017. 

- [378] Guodong Wang, Chenkai Zhang, Qingjie Liu, Jinjin Zhang, Jiancheng Cai, Junjie Liu, and Xinmin Liu. LIBERO-X: Robustness litmus for vision-language-action models. _arXiv preprint arXiv:2602.06556_ , 2026. 

- [379] Haiyang Wang, Yuanyu Zhang, Xinghui Zhu, Ji He, Shuangtrui Zhao, Yulong Shen, and Xiaohong Jiang. Practical spoofing attacks on galileo open service navigation message authentication. _arXiv preprint arXiv:2501.09246_ , 2025. 

- [380] Haoyu Wang, Christopher M. Poskitt, and Jun Sun. AgentSpec: Customizable runtime enforcement for safe and reliable LLM agents. In _ICSE_ , 2026. 

- [381] Huiying Wang, Lisong Zhang, Wenbo Wang, and Yu Wen. Enhancing the robustness of lidar-based object detection under disappearing attacks. In _ICASSP_ , 2025. 

- [382] Jingkang Wang, Ava Pun, James Tu, Sivabalan Manivasagam, Abbas Sadat, Sergio Casas, Mengye Ren, and Raquel Urtasun. Advsim: Generating safety-critical scenarios for self-driving vehicles. In _CVPR_ , 2021. 

- [383] Junran Wang, Xinjie Shen, Zehao Jin, and Pan Li. How far are VLMs from privacy awareness in the physical world? an empirical study. _arXiv preprint arXiv:2605.05340_ , 2026. 

- [384] Kaixiang Wang, Jiong Lou, Zhaojiacheng Zhou, and Jie Li. OEP: Poisoning self-evolving LLM agents via locally correct but non-transferable experiences. _arXiv preprint arXiv:2605.18930_ , 2026. 

67 

- [385] Kun Wang, Guibin Zhang, Zhenhong Zhou, Jiahao Wu, Miao Yu, Shiqian Zhao, Chenlong Yin, Jinhu Fu, Yibo Yan, Hanjun Luo, et al. A comprehensive survey in llm (-agent) full stack safety: Data, training and deployment. _arXiv preprint arXiv:2504.15585_ , 2025. 

- [386] Le Wang, Zonghao Ying, Xiao Yang, Quanchen Zou, Zhenfei Yin, Tianlin Li, Jian Yang, Yaodong Yang, Aishan Liu, and Xianglong Liu. Robosafe: Safeguarding embodied agents via executable safety logic. _arXiv preprint arXiv:2512.21220_ , 2025. 

- [387] Lun Wang, Zaynah Javed, Xian Wu, Wenbo Guo, Xinyu Xing, and Dawn Song. Backdoorl: Backdoor attack against competitive reinforcement learning. In _ĲCAI_ , 2021. 

- [388] Shaojie Wang et al. Adversarial robustness of deep sensor fusion models. In _WACV_ , 2022. 

- [389] Shu Wang, Jiahao Cao, Xu He, Kun Sun, and Qi Li. When the differences in frequency domain are compensated: Understanding and defeating modulated replay attacks on automatic speech recognition. In _CCS_ , 2020. 

- [390] Sicheng Wang, Xu Cheng, Tin Lun Lam, and Tianwei Zhang. Mobile cooperative robot safe interaction method based on embodied perception. In _ICCA_ , 2024. 

- [391] Siyin Wang, Junhao Shi, Zhaoyang Fu, Xinzhe He, Feihong Liu, Chenchen Yang, Yikang Zhou, Zhaoye Fei, Jingjing Gong, Jinlan Fu, Mike Zheng Shou, Xuanjing Huang, Xipeng Qiu, and Yu-Gang Jiang. World action models: The next frontier in embodied AI. _arXiv preprint arXiv:2605.12090_ , 2026. 

- [392] Taowen Wang, Cheng Han, James Chenhao Liang, Wenhao Yang, Dongfang Liu, Luna Xinyu Zhang, Qifan Wang, Jiebo Luo, and Ruixiang Tang. Exploring the adversarial vulnerabilities of vision-language-action models in robotics. In _ICCV_ , 2025. 

- [393] Tianshi Wang, Fengling Li, Yukun Dai, Wencheng Ye, Zhiyong Cheng, and Dongrui Liu. Adversarial robustness in embodied AI: A closed-loop perspective on attacks and defenses. _TechRxiv preprint_ , 2026. 

- [394] Wei Wang, Yao Yao, Xin Liu, Xiang Li, Pei Hao, and Ting Zhu. I can see the light: Attacks on autonomous vehicles using invisible lights. In _CCS_ , 2021. 

- [395] Weizhen Wang, Chenda Duan, Zhenghao Peng, Yuxin Liu, and Bolei Zhou. Embodied scene understanding for vision language models via metavqa. In _CVPR_ , 2025. 

- [396] Xianlong Wang, Hewen Pan, Hangtao Zhang, Minghui Li, Shengshan Hu, Ziqi Zhou, Lulu Xue, Aishan Liu, Yunpeng Jiang, Leo Yu Zhang, et al. Trojanrobot: Physical-world backdoor attacks against vlm-based robotic manipulation. _arXiv preprint arXiv:2411.11683_ , 2024. 

- [397] Xiao Wang, Hanna Krasowski, and Matthias Althoff. Commonroad-rl: A configurable reinforcement learning environment for motion planning of autonomous vehicles. In _ITSC_ , 2021. 

- [398] Xiaohan Wang, Yuehu Liu, Xinhang Song, Beibei Wang, and Shuqiang Jiang. Generating explanations for embodied action decision from visual observation. In _MM_ , 2023. 

- [399] Xin Wang, Jie Li, Zejia Weng, Yixu Wang, Yifeng Gao, Tianyu Pang, Chao Du, Yan Teng, Yingchun Wang, Zuxuan Wu, et al. Freezevla: Action-freezing attacks against vision-language-action models. _arXiv preprint arXiv:2509.19870_ , 2025. 

- [400] Yanting Wang, Hongye Fu, Wei Zou, and Jinyuan Jia. Mmcert. In _CVPR_ , 2024. 

- [401] Yichen Wang, Hangtao Zhang, Hewen Pan, Ziqi Zhou, Xianlong Wang, Peĳin Guo, Lulu Xue, Shengshan Hu, Minghui Li, and Leo Yu Zhang. Advedm: Fine-grained adversarial attack against vlm-based embodied agents. _arXiv preprint arXiv:2509.16645_ , 2025. 

- [402] Yizhou Wang, Libing Wu, Jiong Jin, Enshu Wang, Zhuangzhuang Zhang, and Yu Zhao. An imperceptible adversarial attack against 3d object detectors in autonomous driving. _IEEE Internet of Things Journal (IoT-J)_ , 2025. 

- [403] Yunbo Wang, Cong Sun, Qiaosen Liu, Bingnan Su, Zongxu Zhang, Michael Norris, Gang Tan, and Jianfeng Ma. Vimu: Effective physics-based realtime detection and recovery against stealthy attacks on uavs. In _ACSAC_ , 2024. 

- [404] Yuntao Wang, Xiaolin Niu, Jianle Ba, Zhou Su, and Linkang Du. Navigating embodied intelligence: Enabling technologies, security and privacy, and emerging trends. _IEEE Internet of Things Journal (IoT-J)_ , 2026. 

68 

- [405] Yuqi Wang, Jiawei He, Lue Fan, Hongxin Li, Yuntao Chen, and Zhaoxiang Zhang. Driving into the future: Multiview visual forecasting and planning with world model for autonomous driving. In _CVPR_ , 2024. 

- [406] Zhiwen Wang, Yuhui Wu, Zheng Wang, Jiwei Wei, Tianyu Li, Guoqing Wang, Yang Yang, and Hengtao Shen. Cascaded adversarial attack: Simultaneously fooling rain removal and semantic segmentation networks. In _MM_ , 2024. 

- [407] Zihan Wang, Rui Zhang, Yu Liu, Chi Liu, Qingchuan Zhao, Hongwei Li, and Guowen Xu. Black-box skill stealing attack from proprietary LLM agents: An empirical study. _arXiv preprint arXiv:2604.21829_ , 2026. 

- [408] Zixia Wang, Jia Hu, and Ronghui Mu. Safety of embodied navigation: A survey. _arXiv preprint arXiv:2508.05855_ , 2025. 

- [409] Congcong Wen, Jiazhao Liang, Shuaihang Yuan, Hao Huang, Geeta Chandra Raju Bethala, Yu-Shen Liu, Mengyu Wang, Anthony Tzes, and Yi Fang. How secure are large language models (llms) for navigation in urban environments? _arXiv preprint arXiv:2402.09546_ , 2024. 

- [410] Junjie Wen, Yichen Zhu, Jinming Li, Minjie Zhu, Zhibin Tang, Kun Wu, Zhiyuan Xu, Ning Liu, Ran Cheng, Chaomin Shen, et al. Tinyvla: Towards fast, data-efficient vision-language-action models for robotic manipulation. _IEEE Robotics and Automation Letters (RA-L)_ , 2025. 

- [411] Junjie Wen, Yichen Zhu, Minjie Zhu, Zhibin Tang, Jinming Li, Zhongyi Zhou, Xiaoyu Liu, Chaomin Shen, Yaxin Peng, and Feifei Feng. Diffusionvla: Scaling robot foundation models via unified diffusion and autoregression. In _ICML_ , 2025. 

- [412] Tsui-Wei Weng, Jonathan Uesato, Kai Xiao, Sven Gowal, Robert Stanforth, and Pushmeet Kohli. Toward evaluating robustness of deep reinforcement learning with continuous control. In _ICLR_ , 2020. 

- [413] Henry Wong, Clement Fung, Weiran Lin, Karen Li, Stanley Chen, and Lujo Bauer. Attacking autonomous driving agents with adversarial machine learning: A holistic evaluation with the carla leaderboard. _arXiv preprint arXiv:2511.14876_ , 2025. 

- [414] Fan Wu, Linyi Li, Zĳian Huang, Yevgeniy Vorobeychik, Ding Zhao, and Bo Li. Crop: Certifying robust policies for reinforcement learning through functional smoothing. In _ICLR_ , 2022. 

- [415] Han Wu, Syed Yunas, Sareh Rowlands, Wenjie Ruan, and Johan Wahlström. Adversarial driving: Attacking end-to-end autonomous driving. In _IV_ , 2021. 

- [416] Han Wu, Syed Yunas, Sareh Rowlands, Wenjie Ruan, and Johan Wahlstrom. Adversarial detection: Attacking object detection in real time. In _IV_ , 2023. 

- [417] Han Wu, Sareh Rowlands, and Johan Wahlstrom. A human-in-the-middle attack against object detection systems. _Artificial Intelligence (AĲ)_ , 2024. 

- [418] Shanglin Wu and Kai Shu. Memory in llm-based multi-agent systems: Mechanisms, challenges, and collective intelligence. _Authorea Preprints_ , 2025. 

- [419] Shutong Wu, Jiongxiao Wang, Wei Ping, Weili Nie, and Chaowei Xiao. Defending against adversarial audio via diffusion model. _arXiv preprint arXiv:2303.01507_ , 2023. 

- [420] Wenxi Wu, Fabio Pierazzi, Yali Du, and Martim Brand ao. Characterizing physical adversarial attacks on robot motion planners. In _ICRA_ , 2024. 

- [421] Yi Wu, Zikang Xiong, Yiran Hu, Shreyash S. Iyengar, Nan Jiang, Aniket Bera, Lin Tan, and Suresh Jagannathan. Generating safe and efficient task plans for robot agents with large language models. _arXiv preprint_ , 2024. 

- [422] Yutao Wu, Xiao Liu, Yifeng Gao, Xiang Zheng, Hanxun Huang, Yige Li, Cong Wang, Bo Li, Xingjun Ma, and Yu-Gang Jiang. Internal safety collapse in frontier large language models. _arXiv preprint arXiv:2603.23509_ , 2026. 

- [423] Zhishang Xiang, Chengyi Yang, Zerui Chen, Zhimin Wei, Yunbo Tang, Zongpei Teng, Zexi Peng, Zongxia Li, Chengsong Huang, Yicheng He, Chang Yang, Xinrun Wang, Xiao Huang, Qinggang Zhang, and Jinsong Su. A systematic survey of self-evolving agents: From model-centric to environment-driven co-evolution. _TechRxiv preprint_ , 2025. 

69 

- [424] Qifan Xiao, Xudong Pan, Yifan Lu, Mi Zhang, Jiarun Dai, and Min Yang. Exorcising “wraith”: Protecting lidar-based object detector in automated driving system from appearing attacks. In _USENIX Security_ , 2023. 

- [425] Wenjie Xiao, Xuehai Tang, Biyu Zhou, Songlin Hu, and Jizhong Han. RouteGuard: Internal-signal detection of skill poisoning in LLM agents. _arXiv preprint arXiv:2604.22888_ , 2026. 

- [426] Mingyang Xie and Jin Wei-Kocsis. From prompt to physical action: Structured backdoor attacks on LLM-mediated robotic control systems. _arXiv preprint arXiv:2604.03890_ , 2026. 

- [427] Yuhan Xie, Yuping Yan, Yunqi Zhao, Handing Wang, and Yaochu Jin. STRONG-VLA: Decoupled robustness learning for vision-language-action models under multimodal perturbations. _arXiv preprint arXiv:2604.10055_ , 2026. 

- [428] Yuting Xie, Xianda Guo, Cong Wang, Kunhua Liu, and Long Chen. Advdiffuser: Generating adversarial safety-critical driving scenarios via guided diffusion. In _IROS_ , 2024. 

- [429] Wenpeng Xing, Minghao Li, Mohan Li, and Meng Han. Towards robust and secure embodied ai: A survey on vulnerabilities and attacks. _ACM Computing Surveys_ , 2026. 

- [430] Yanming Xiu, Zhengyuan Jiang, Neil Zhenqiang Gong, and Maria Gorlatova. Benchmarking vision-language models under contradictory virtual content attacks in augmented reality. _arXiv preprint arXiv:2604.05510_ , 2026. 

- [431] Bingxin Xu, Yuzhang Shang, Binghui Wang, and Emilio Ferrara. SilentDrift: Exploiting action chunking for stealthy backdoor attacks on vision-language-action models. _arXiv preprint arXiv:2601.14323_ , 2026. 

- [432] Chejian Xu, Wenhao Ding, Weĳie Lyu, Zuxin Liu, Shuai Wang, Yihan He, Hanjiang Hu, Ding Zhao, and Bo Li. Safebench: A benchmarking platform for safety evaluation of autonomous vehicles. In _NeurIPS_ , 2022. 

- [433] Haochuan Xu, Yun Sing Koh, Shuhuai Huang, Zirun Zhou, Di Wang, J. Sakuma, and Jingfeng Zhang. Model-agnostic adversarial attack and defense for vision-language-action models. _arXiv preprint arXiv:2510.13237_ , 2025. 

- [434] Henry Xu, An Ju, and David Wagner. Model-agnostic defense for lane detection against adversarial attack. _arXiv preprint arXiv:2103.00663_ , 2021. 

- [435] Kaidi Xu, Gaoyuan Zhang, Sĳia Liu, Quanfu Fan, Mengshu Sun, Hongge Chen, Pin-Yu Chen, Yanzhi Wang, and Xue Lin. Adversarial t-shirt! evading person detectors in a physical world. In _ECCV_ , 2020. 

- [436] Sheng Xu and Guiliang Liu. Robust inverse constrained reinforcement learning under model misspecification. In _ICML_ , 2024. 

- [437] Shuhan Xu, Siyuan Liang, Hongling Zheng, Yong Luo, Han Hu, Lefei Zhang, and Dacheng Tao. CtrlAttack: A unified attack on world-model control in diffusion models. _arXiv preprint arXiv:2603.13435_ , 2026. 

- [438] Wenyuan Xu, Chen Yan, Weibin Jia, Xiaoyu Ji, and Jianhao Liu. Analyzing and enhancing the security of ultrasonic sensors for autonomous vehicles. _IEEE Internet of Things Journal (IoT-J)_ , 2018. 

- [439] Wujiang Xu, Zujie Liang, Kai Mei, Hang Gao, Juntao Tan, and Yongfeng Zhang. A-mem: Agentic memory for llm agents. In _NeurIPS_ , 2025. 

- [440] Zonghuan Xu, Jiayu Li, Yunhan Zhao, Xiang Zheng, Xingjun Ma, and Yu-Gang Jiang. DropVLA: An action-level backdoor attack on vision-language-action models. _arXiv preprint arXiv:2510.10932_ , 2025. 

- [441] Nian Xue, Liang Niu, Xianbin Hong, Zhen Li, Larissa Hoffaeller, and Christina Pöpper. Deepsim: Gps spoofing detection on uavs using satellite imagery matching. In _ACSAC_ , 2020. 

- [442] Jean-Paul A. Yaacoub, Hassan N. Noura, Ola Salman, and A. Chehab. Robotics cyber security: Vulnerabilities, attacks, countermeasures, and recommendations. _International Journal of Information Security_ , 2021. 

- [443] Bo Yan, Weikai Lin, Yada Zhu, and Song Wang. SafeDream: Safety world model for proactive early jailbreak detection. _arXiv preprint arXiv:2604.16824_ , 2026. 

- [444] Chen Yan, Wenyuan Xu, and Jianhao Liu. Can you trust autonomous vehicles: Contactless attacks against sensors of self-driving vehicle. _DEF CON_ , 2016. 

- [445] Yuping Yan, Yuhan Xie, Yixin Zhang, Lingjuan Lyu, Handing Wang, and Yaochu Jin. When alignment fails: Multimodal adversarial attacks on vision-language-action models. _arXiv preprint arXiv:2511.16203_ , 2025. 

70 

- [446] Jirui Yang, Zheyu Lin, Zhihui Lu, Yinggui Wang, Lei Wang, Tao Wei, Qiang Duan, Xin Du, and Shuhan Yang. CEE: An inference-time jailbreak defense for embodied intelligence via subspace concept rotation. _arXiv preprint arXiv:2504.13201_ , 2025. 

- [447] Rui Yang, Jie Wang, Guoping Wu, and Bin Li. Uncertainty-based offline variational bayesian reinforcement learning for robustness under diverse data corruptions. In _NeurIPS_ , 2024. 

- [448] Rui Yang, Han Zhong, Jiawei Xu, Amy Zhang, Chongjie Zhang, Lei Han, and Tong Zhang. Towards robust offline reinforcement learning under diverse data corruption. In _ICLR_ , 2024. 

- [449] Rui Yang, Hanyang Chen, Junyu Zhang, Mark Zhao, Cheng Qian, Kangrui Wang, Qineng Wang, Teja Venkat Koripella, M. Movahedi, Manling Li, Heng Ji, Huan Zhang, and Tong Zhang. Embodiedbench: Comprehensive benchmarking multi-modal large language models for vision-driven embodied agents. _arXiv preprint_ , 2025. 

- [450] Shengyuan Yang, Jiawang Bai, Yong Li, et al. Not all prompts are secure: A switchable backdoor attack against pre-trained vision transformers. In _CVPR_ , 2024. 

- [451] Xiaofang Yang, Lĳun Li, Heng Zhou, Tong Zhu, Xiaoye Qu, Yuchen Fan, Qianshan Wei, Rui Ye, Li Kang, Yiran Qin, et al. Toward efficient agents: Memory, tool learning, and planning. _arXiv preprint arXiv:2601.14192_ , 2026. 

- [452] Zhuolin Yang, Bo Li, Pin-Yu Chen, and Dawn Song. Towards mitigating audio adversarial perturbations. _arXiv preprint arXiv:1806.02776_ , 2018. 

- [453] Ziyi Yang, Shreyas S. Raman, Ankit Shah, and Stefanie Tellex. Plug in the safety chip: Enforcing constraints for llm. _Brown University Technical Report_ , 2024. 

- [454] Mang Ye, Xuankun Rong, Wenke Huang, Bo Du, Nenghai Yu, and Dacheng Tao. A survey of safety on large vision-language models: Attacks, defenses and evaluations. _arXiv preprint arXiv:2502.14881_ , 2025. 

- [455] Doguhan Yeke, Kartik A. Pant, Muslum Ozgur Ozmen, Hyungsub Kim, James M. Goppert, Inseok Hwang, Antonio Bianchi, and Z. Berkay Celik. Automated discovery of semantic attacks in multi-robot navigation. In _USENIX Security_ , 2025. 

- [456] Doguhuan Yeke, Yanming Zhou, Leo Y. Lin, Hongyu Cai, Antonio Bianchi, and Z. Berkay Celik. RoboJailBench: Benchmarking adversarial attacks and defenses in embodied robotic agents. _arXiv preprint arXiv:2605.19328_ , 2026. 

- [457] Sheng Yin, Xianghe Pang, Yuanzhuo Ding, Menglan Chen, Yutong Bi, Yichen Xiong, Wenhao Huang, Zhen Xiang, Jing Shao, and Siheng Chen. Safeagentbench: A benchmark for safe task planning of embodied llm agents. _arXiv preprint arXiv:2412.13178_ , 2024. 

- [458] Zonghao Ying, Le Wang, Yisong Xiao, Jiakai Wang, Yuqing Ma, Jinyang Guo, Zhenfei Yin, Mingchuan Zhang, Aishan Liu, and Xianglong Liu. Agentsafe: Benchmarking the safety of embodied agents on hazardous instructions. _arXiv preprint arXiv:2506.14697_ , 2025. 

- [459] Kota Yoshida, Masaya Hojo, and Takeshi Fujino. Adversarial scan attack against scan matching algorithm for pose estimation in lidar-based slam. _Science_ , 2022. 

- [460] Chengzeng You, Zhongyuan Hau, and Soteris Demetriou. Temporal consistency checks to detect lidar spoofing attacks on autonomous vehicle perception. In _MAISP_ , 2021. 

- [461] Haoyi You, Beichen Yu, Haiming Jin, Zhaoxing Yang, Jiahui Sun, and Xinbing Wang. User-oriented robust reinforcement learning. In _AAAI_ , 2023. 

- [462] Zhiyuan Yu, Shixuan Zhai, and Ning Zhang. Antifake: Using adversarial audio to prevent unauthorized speech synthesis. In _CCS_ , 2023. 

- [463] Lei Yuan, Ziqian Zhang, Ke Xue, Hao Yin, Feng Chen, Cong Guan, Lihe Li, Chao Qian, and Yang Yu. Robust multi-agent coordination via evolutionary generation. In _AAAI_ , 2023. 

- [464] Xuejing Yuan, Yuxuan Chen, Yue Zhao, Yunhui Long, Xiaokang Liu, Kai Chen, Shengzhi Zhang, Heqing Huang, Xiaofeng Wang, and Carl A. Gunter. Commandersong: A systematic approach for practical adversarial voice recognition. In _USENIX Security_ , 2018. 

- [465] Zenghui Yuan, Pan Zhou, Kai Zou, and Yu Cheng. You are catching my attention: Are vision transformers bad learners under backdoor attacks? In _CVPR_ , 2023. 

71 

- [466] Ekim Yurtsever, Yongkang Liu, Jacob Lambert, Chiyomi Miyajima, Eĳiro Takeuchi, Kazuya Takeda, and John HL Hansen. Risky action recognition in lane change video clips using deep spatiotemporal networks with segmentation mask transfer. In _ITSC_ , 2019. 

- [467] Qiang Zeng, Jianhai Su, Chenglong Fu, Golam Kayas, Lannan Luo, Xiaojiang Du, Chiu C Tan, and Jie Wu. A multiversion programming inspired approach to detecting audio adversarial examples. In _DSN_ , 2019. 

- [468] Xinyu Zeng, Xiangkun He, Lei Tao, Chen Lv, and Hong Cheng. Adversarial flow matching for imperceptible attacks on end-to-end autonomous driving. _arXiv preprint arXiv:2605.00880_ , 2026. 

- [469] Qiusi Zhan, Hyeonjeong Ha, Rui Yang, Sirui Xu, Hanyang Chen, Liangyan Gui, Yu-Xiong Wang, Huan Zhang, Heng Ji, and Daniel Kang. Beat: Visual backdoor attacks on vlm-based embodied agents via contrastive trigger learning. In _ICLR_ , 2026. 

- [470] Borong Zhang, Yuhao Zhang, Jiaming Ji, Yingshan Lei, Josef Dai, Yuanpei Chen, and Yaodong Yang. Safevla: Towards safety alignment of vision-language-action model via constrained learning. In _NeurIPS_ , 2025. 

- [471] Guibin Zhang, Hejia Geng, Xiaohang Yu, Zhenfei Yin, Zaibin Zhang, Zelin Tan, et al. The landscape of agentic reinforcement learning for LLMs: A survey. _arXiv preprint arXiv:2509.02547_ , 2025. 

- [472] Hangtao Zhang, Chenyu Zhu, Xianlong Wang, Ziqi Zhou, Changgan Yin, Minghui Li, Lulu Xue, Yichen Wang, Shengshan Hu, Aishan Liu, et al. Badrobot: Jailbreaking embodied llms in the physical world. _arXiv preprint arXiv:2407.20242_ , 2024. 

- [473] Huan Zhang, Hongge Chen, Chaowei Xiao, Bo Li, Mingyan Liu, Duane S. Boning, and Cho-Jui Hsieh. Robust deep reinforcement learning against adversarial perturbations. In _NeurIPS_ , 2020. 

- [474] Huan Zhang, Hongge Chen, Duane Boning, and Cho-Jui Hsieh. Robust reinforcement learning on state observations with learned optimal adversary. In _ICLR_ , 2021. 

- [475] Jiaming Zhang, Junhong Ye, Xingjun Ma, Yige Li, Yunfan Yang, Yunhao Chen, Jitao Sang, and Dit-Yan Yeung. AnyAttack: Towards large-scale self-supervised adversarial attacks on vision-language models. In _CVPR_ , 2025. 

- [476] Jiaqi Zhang, Chen Gao, Liyuan Zhang, Quoc Viet Hung Nguyen, and Hongzhi Yin. Smartagent: Chain-of-userthought for embodied personalized agent in cyber world. In _AAAI_ , 2026. 

- [477] Jingyu Zhang, Jacky Wai Keung, Yan Xiao, Yihan Liao, Yishu Li, and Xiaoxue Ma. Uniada: Universal adaptive multiobjective adversarial attack for end-to-end autonomous driving systems. _IEEE Transactions on Reliability_ , 2024. 

- [478] Jinlai Zhang, Lyujie Chen, Bo Ouyang, Binbin Liu, Jihong Zhu, Yujin Chen, Yanmei Meng, and Danfeng Wu. Pointcutmix: Regularization strategy for point cloud classification. _Neurocomputing_ , 2022. 

- [479] Mengyuan Zhang, Shibo He, Chaoqun Yang, Jiming Chen, and Junshan Zhang. Vanet-assisted interference mitigation for millimeter-wave automotive radar sensors. _IEEE Network_ , 2020. 

- [480] Mingxuan Zhang, Oubo Ma, Kang Wei, Songze Li, and Shouling Ji. Toobadrl: Trigger optimization to boost effectiveness of backdoor attacks on deep reinforcement learning. _arXiv preprint arXiv:2506.09562_ , 2025. 

- [481] Naifu Zhang, Wei Tao, Xi Xiao, Qianpu Sun, Yuxin Zheng, Wentao Mo, Pei Wang, and Nan Zhang. Attention-guided patch-wise sparse adversarial attacks on vision-language-action models. _arXiv preprint arXiv:2511.21663_ , 2025. 

- [482] Qingzhao Zhang, Shengtuo Hu, Jiachen Sun, Qi Alfred Chen, and Z Morley Mao. On adversarial robustness of trajectory prediction for autonomous vehicles. In _CVPR_ , 2022. 

- [483] Qingzhao Zhang, Shaocheng Luo, Z. Morley Mao, Miroslav Pajic, and Michael K. Reiter. SoK: How sensor attacks disrupt autonomous vehicles: An end-to-end analysis, challenges, and missed threats. _arXiv preprint arXiv:2509.11120_ , 2025. 

- [484] Rongjunchen Zhang, Xiao Chen, Sheng Wen, and James Zheng. Who activated my voice assistant? a stealthy attack on android phones without users’ awareness. In _ML4CS_ , 2019. 

- [485] Shuning Zhang, Lyumanshan Ye, Xin Yi, Jingyu Tang, Bo Shui, Haobin Xing, Pengfei Liu, and Hewu Li. Ghost of the past: Identifying and resolving privacy leakage of LLM’s memory through proactive user interaction. _arXiv preprint arXiv:2410.14931_ , 2024. 

72 

- [486] Tao Zhang, Kaixian Qu, Zhibin Li, Jiajun Wu, Marco Hutter, Manling Li, and Fan Shi. Using large language models for embodied planning introduces systematic safety risks. _arXiv preprint arXiv:2604.18463_ , 2026. 

- [487] Tianwei Zhang, Huayan Zhang, Xiaofei Li, Junfeng Chen, Tin Lun Lam, and Sethu Vĳayakumar. Acousticfusion: Fusing sound source localization to visual slam in dynamic environments. In _IROS_ , 2021. 

- [488] Tianyuan Zhang, Lu Wang, Xinwei Zhang, Yitong Zhang, Boyi Jia, Siyuan Liang, Shengshan Hu, Qiang Fu, Aishan Liu, and Xianglong Liu. Visual adversarial attack on vision-language models for autonomous driving. _arXiv preprint arXiv:2411.18275_ , 2024. 

- [489] Wenxiao Zhang, Xiangrui Kong, Thomas Braunl, and Jin B Hong. Safeembodai: a safety framework for mobile robots in embodied ai systems. _arXiv preprint arXiv:2409.01630_ , 2024. 

- [490] Wenxiao Zhang, Xiangrui Kong, Conan Dewitt, Thomas Braunl, and Jin B Hong. A study on prompt injection attack against llm-integrated mobile robotic systems. In _ISSREW_ , 2024. 

- [491] Wenxiao Zhang, Xiangrui Kong, Conan Dewitt, and Michael Bräunig. Enhancing reliability in llm-integrated robotic systems. _Journal of Systems and Software_ , 2025. 

- [492] Xinwei Zhang, Aishan Liu, Tianyuan Zhang, Siyuan Liang, and Xianglong Liu. Towards robust physical-world backdoor attacks on lane detection. In _MM_ , 2024. 

- [493] Yan Zhang, Yi Zhu, Zihao Liu, Chenglin Miao, Foad Hajiaghajani, Lu Su, and Chunming Qiao. Towards backdoor attacks against lidar object detection in autonomous driving. In _SenSys_ , 2022. 

- [494] Yan Zhang, Zihao Liu, Yi Zhu, and Chenglin Miao. Towards real-time defense against object-based lidar attacks in autonomous driving. In _CCS_ , 2025. 

- [495] Yang Zhang, Hassan Foroosh, Philip David, and Boqing Gong. Camou: Learning physical vehicle camouflages to adversarially attack detectors in the wild. In _ICLR_ , 2018. 

- [496] Yifan Zhang, Junhui Hou, and Yixuan Yuan. A comprehensive study of the robustness for lidar-based 3d object detectors against adversarial attacks. _International Journal of Computer Vision (ĲCV)_ , 2024. 

- [497] Yu Zhang, Gongbo Liang, Tawfiq Salem, and Nathan Jacobs. Defense-pointnet: Protecting pointnet against adversarial attacks. In _Big Data_ , 2019. 

- [498] Yuhao Zhang, Borong Zhang, Jiaming Fan, Jiachen Shen, Yishuai Cai, Yaodong Yang, and Jiaming Ji. RedVLA: Physical red teaming for vision-language-action models. _arXiv preprint arXiv:2604.22591_ , 2026. 

- [499] Yuxuan Zhang, Zhenbo Shi, Shuchang Wang, Wei Yang, Shaowei Wang, and Yinxing Xue. Rp-pgd: Boosting segmentation robustness with a region-and-prototype based adversarial attack. In _AAAI_ , 2025. 

- [500] Zaibin Zhang, Yongting Zhang, Lĳun Li, Hongzhi Gao, Lĳun Wang, Huchuan Lu, Feng Zhao, Yu Qiao, and Jing Shao. Psysafe: A comprehensive framework for psychological-based attack, defense, and evaluation of multi-agent system safety. In _ACL_ , 2024. 

- [501] Zeyu Zhang, Xiaohe Bo, Chen Ma, Rui Li, Xu Chen, Quanyu Dai, Jieming Zhu, Zhenhua Dong, and Ji-Rong Wen. A survey on the memory mechanism of large language model-based agents. _ACM Transactions on Information Systems_ , 2025. 

- [502] Zeyu Zhang, Sixu Yan, Muzhi Han, Zaĳin Wang, Xinggang Wang, Song-Chun Zhu, and Hangxin Liu. M3bench: Benchmarking whole-body motion generation for mobile manipulation in 3d scenes. _IEEE Robotics and Automation Letters (RA-L)_ , 2025. 

- [503] Zhexin Zhang, Shiyao Cui, Yida Lu, Jingzhuo Zhou, Junxiao Yang, Hongning Wang, and Minlie Huang. Agentsafetybench: Evaluating the safety of llm agents. _arXiv preprint arXiv:2412.14470_ , 2024. 

- [504] Ke Zhao, Huayang Huang, Miao Li, and Yu Wu. Rethinking the intermediate features in adversarial attacks: Misleading robotic models via adversarial distillation. _arXiv preprint arXiv:2411.15222_ , 2024. 

- [505] Yunhan Zhao, Xiang Zheng, Lin Luo, Yige Li, Xingjun Ma, and Yu-Gang Jiang. BlueSuffix: Reinforced blue teaming for vision-language models against jailbreak attacks. In _ICLR_ , 2025. 

73 

- [506] Baolin Zheng, Peipei Jiang, Qian Wang, Qi Li, Chao Shen, Cong Wang, Yunjie Ge, Qingyang Teng, and Shenyi Zhang. Black-box adversarial attacks on commercial speech platforms with minimal information. In _CCS_ , 2021. 

- [507] Junhao Zheng, Chengming Shi, Xidi Cai, Qiuke Li, Duzhen Zhang, Chenxing Li, Dong Yu, and Qianli Ma. Lifelong learning of large language model based agents: A roadmap. _arXiv preprint arXiv:2501.07278_ , 2025. 

- [508] Mengxin Zheng, Qian Lou, and Lei Jiang. TrojViT: Trojan insertion in vision transformers. In _CVPR_ , 2023. 

- [509] Shĳun Zheng, Weiquan Liu, Yu Guo, Yu Zang, Siqi Shen, and Cheng Wang. A new adversarial perspective for lidar-based 3d object detection. In _AAAI_ , 2025. 

- [510] Xiang Zheng, Xingjun Ma, Shengjie Wang, Xinyu Wang, Chao Shen, and Cong Wang. Toward evaluating robustness of reinforcement learning with adversarial policy. In _DSN_ , 2024. 

- [511] Xiang Zheng, Yutao Wu, Hanxun Huang, Yige Li, Xingjun Ma, Bo Li, Yu-Gang Jiang, and Cong Wang. Just ask: Curious code agents reveal system prompts in frontier LLMs. _arXiv preprint arXiv:2601.21233_ , 2026. 

- [512] Zhihao Zheng, Xiaowen Ying, Zhen Yao, and Mooi Choo Chuah. Robustness of trajectory prediction models under map-based attacks. In _WACV_ , 2023. 

- [513] Minghan Zhong, Hong Li, and Mingquan Lu. Analysis and validation of distributed gnss spoofing threat. _Engineering Proceedings_ , 2025. 

- [514] Ce Zhou, Qiben Yan, Yan Shi, and Lichao Sun. Doublestar: Long-range attack towards depth estimation based obstacle avoidance in autonomous systems. In _USENIX Security_ , 2022. 

- [515] Chenyu Zhou, Huacan Chai, Wenteng Chen, Zihan Guo, Rong Shan, Yuanyi Song, Tianyi Xu, Yingxuan Yang, Aofan Yu, Weiming Zhang, Congming Zheng, Jiachen Zhu, Zeyu Zheng, Zhuosheng Zhang, Xingyu Lou, Changwang Zhang, Zhihui Fu, Jun Wang, Weiwen Liu, Jianghao Lin, and Weinan Zhang. Externalization in LLM agents: A unified review of memory, skills, protocols and harness engineering. _arXiv preprint arXiv:2604.08224_ , 2026. 

- [516] Hao Zhou, Tiru Wu, Yan Jiang, Wanqi Zhou, Junxing Hu, and Ai Han. Hierarchical attacks for multi-modal multi-agent reasoning. In _CVPR_ , 2026. 

- [517] Lifeng Zhou and Pratap Tokekar. Multi-robot coordination and planning in uncertain and adversarial environments. _Robotics_ , 2021. 

- [518] Ruida Zhou, Tao Liu, Min Cheng, Dileep Kalathil, P. R. Kumar, and Chao Tian. Natural actor-critic for robust reinforcement learning with function approximation. In _NeurIPS_ , 2023. 

- [519] Siqi Zhou, Sotiris Papatheodorou, Stefan Leutenegger, and Angela P Schoellig. Control-barrier-aided teleoperation with visual-inertial slam for safe mav navigation in complex environments. In _ICRA_ , 2024. 

- [520] Wenlong Zhou, Zhiwei Lv, Wenbo Wu, Xiangyong Shang, and Ye Ke. Anti-spoofing technique based on vector tracking loop. _IEEE Transactions on Instrumentation and Measurement_ , 2023. 

- [521] Xingcheng Zhou, Xuyuan Han, Feng Yang, Yunpu Ma, and Alois C Knoll. Opendrivevla: Towards end-to-end autonomous driving with large vision language action model. _arXiv preprint arXiv:2503.23463_ , 2025. 

- [522] Xueyang Zhou, Guiyao Tie, Guowen Zhang, Hecheng Wang, Pan Zhou, and Lichao Sun. Badvla: Towards backdoor attacks on vision-language-action models via objective-decoupled optimization. In _NeurIPS_ , 2025. 

- [523] Zirun Zhou, Zhengyang Xiao, Haochuan Xu, Jingwei Sun, Di Wang, and Jingfeng Zhang. Goal-oriented backdoor attack against vision-language-action models via physical objects. _arXiv preprint arXiv:2510.09269_ , 2025. 

- [524] Ziyuan Zhou, Guanjun Liu, and Mengchu Zhou. A robust mean-field actor-critic reinforcement learning against adversarial perturbations. _IEEE Transactions on Neural Networks and Learning Systems (TNNLS)_ , 2023. 

- [525] Shenchen Zhu, Yue Zhao, Kai Chen, Bo Wang, Hualong Ma, and Cheng’an Wei. AE-Morpher: Improve physical robustness of adversarial objects against LiDAR-based detectors via object reconstruction. In _USENIX Security_ , 2024. 

- [526] Xiaopei Zhu, Guanning Zeng, Zhanhao Hu, Jun Zhu, and Xiaolin Hu. Physical adversarial clothing evades visible-thermal detectors via non-overlapping RGB-T pattern. _arXiv preprint arXiv:2605.04675_ , 2026. 

- [527] Yi Zhu, Chenglin Miao, Hongfei Xue, Zhengxiong Li, Yunnan Yu, Wenyao Xu, Lu Su, and Chunming Qiao. Tilemask: A passive-reflection-based attack against mmwave radar object detection in autonomous driving. In _CCS_ , 2023. 

74 

- [528] Yi Zhu, Chenglin Miao, Hongfei Xue, Yunnan Yu, Lu Su, and Chunming Qiao. Malicious attacks against multi-sensor fusion in autonomous driving. In _MobiCom_ , 2024. 

- [529] Haomin Zhuang, Hanwen Xing, Yujun Zhou, Yuchen Ma, Yue Huang, Yili Shen, Yufei Han, and Xiangliang Zhang. AgentTrap: Measuring runtime trust failures in third-party agent skills. _arXiv preprint arXiv:2605.13940_ , 2026. 

- [530] Geigh Zollicoffer, Tanush Chopra, Mingkuan Yan, Xiaoxu Ma, Kenneth Eaton, and Mark Riedl. World model robustness via surprise recognition. _arXiv preprint arXiv:2512.01119_ , 2025. 

- [531] Wei Zong, Yang-Wai Chow, Willy Susilo, Kien Do, and Svetha Venkatesh. Trojanmodel: A practical trojan attack against automatic speech recognition systems. In _S&P_ , 2023. 

- [532] Henry Peng Zou, Wei-Chieh Huang, Yaozu Wu, Yankai Chen, Chunyu Miao, Hoang Nguyen, Yue Zhou, Weizhi Zhang, Liancheng Fang, Langzhou He, Yangning Li, Dongyuan Li, Renhe Jiang, Xue Liu, and Philip S. Yu. LLM-based human-agent collaboration and interaction systems: A survey. _arXiv preprint arXiv:2505.00753_ , 2025. 

- [533] Rui Zou, Yubin Liu, Ying Li, Guoqing Chu, Jie Zhao, and H. Cai. A novel human intention prediction approach based on fuzzy rules through wearable sensing in human–robot handover. _Robotics_ , 2023. 

75 

