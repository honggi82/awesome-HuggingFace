### arXiv:2509.11481v2[cs.RO]6Apr2026

## RAPTOR: A Foundation Policy for Quadrotor Control

Jonas Eschmann1∗, Dario Albani2, Giuseppe Loianno1

1EECS, UC Berkeley, USA. 2ARRC, Technology Innovation Institute, UAE. ∗Corresponding author. Email: jonas.eschmann@berkeley.edu

Project Page: https://raptor.rl.tools Video: https://youtu.be/hVzdWRFTX3k

Humans are remarkably data-efficient when adapting to new unseen conditions, like driving a new car. In contrast, modern robotic control systems, like neural network policies trained using Reinforcement Learning (RL), are highly specialized for single environments. Because of this overfitting, they are known to break down even under small differences like the Simulation-to-Reality (Sim2Real) gap and require system identification and retraining for even minimal changes to the system. In this work, we present RAPTOR, a method for training a highly adaptive foundation policy for quadrotor control. Our method enables training a single, end-to-end neural-network policy to control a wide variety of quadrotors. We test 10 different real quadrotors from 32 g to 2.4 kg that also differ in motor type (brushed vs. brushless), frame type (soft vs. rigid), propeller type (2/3/4-blade), and flight controller (PX4/Betaflight/Crazyflie/M5StampFly). We find that a tiny, three-layer policy with only 2084 parameters is sufficient for zero-shot adaptation to a wide variety of platforms. The adaptation through in-context learning is made possible by using a recurrence in the hidden layer. The policy is trained through our proposed Meta-Imitation Learning algorithm, where we sample 1000 quadrotors and train a teacher policy for each of them using RL. Subsequently, the 1000 teachers are distilled into a single, adaptive student policy. We find that within milliseconds, the resulting foundation policy adapts zero-shot to unseen quadrotors. We extensively test the capabilities of the foundation policy under numerous conditions (trajectory tracking, indoor/outdoor, wind disturbance, poking, different propellers).

#### Introduction

Bearing Vertical Take-Off and Landing (VTOL) and hovering capabilities, Multirotor Aerial Vehicles (MAVs) have become a valuable platform for many real-world applications like package delivery (1), infrastructure inspection and maintenance (2), or search and rescue (3). In addition to the VTOL and hovering capabilities, MAVs can be built from cheap, mass-produced Commercial Off-The-Shelf (COTS) parts and can be scaled from light (tens of grams) and centimeter-sized to heavy (multiple kilograms) and meter-sized. This broad range allows for easy customization of the mechanical and electrical design for each particular application.

###### Human Reinforcement Learning

[Figure 1]

[Figure 2]

Pre-training: 1000 teacher policies

~115 days of simulated experience

~ 6h of driving school

~1-10h of simulated experience dynamics: same as in simulation different

###### Post-training Distillation

|p R(q) v ω a| |
|---|---|
| | |

10 minutes of adaptation

|Teacher|
|---|

|SysID|
|---|

|Teacher| |
|---|---|
| | |

|Foundation Policy| |
|---|---|
| | |

[Figure 3]

|Teacher|
|---|

|a : RPMs|
|---|

...

re-training

zero-shotadaptation

[Figure 4]

[Figure 5]

[Figure 6]

[Figure 7]

different accelerator/brake/steering response

[Figure 8]

- A
- B

RL Pre-Training Meta-Imitation Learning Deployment

|dynamicsdistribution<br><br>|
|---|

[Figure 9]

observation

[Figure 10]

~ ~ ~ ~

|Teacher Policy|
|---|

state

[Figure 11]

action

action

reward

action

[Figure 12]

Random Init

###### MSE

[Figure 13]

observation

[Figure 14]

|Teacher Policy|
|---|

state

action

dynamicsdistribution

[Figure 15]

action

reward

action

|Student Policy<br><br>= Foundation Policy|
|---|

###### MSE

observation

[Figure 16]

|Teacher Policy|
|---|

state

action

[Figure 17]

action

action

reward

[Figure 18]

###### MSE

[Figure 19]

observation

[Figure 20]

state

|Teacher Policy|
|---|

action

action

reward

action

###### MSE

###### backward

# ...

# ...

# ...

∉

1000x

1000x

1000x

Figure 1: (A) Motivation. Comparison of the adaptation1 capabilities of humans, contemporary RL-based control policies, and our RAPTOR method. (B) The RAPTOR Method. Overview of all stages of the RAPTOR architecture.

On the other hand, this variability also leads to challenges concerningthe control of theplatform. Changing the mechanical design and even simple modifications like switching the propeller or battery type often require the retuning of the cascade of classical controllers that is still most widely used today. Analogously, modern, nonlinear control approaches, like Model Predictive Control (MPC) or Reinforcement Learning, heavily rely on accurate system models.

Reinforcement Learning (RL) policies have recently gained widespread popularity for quadrotor control(4,5,6,7).Althoughovercomingmanychallenges,theresultingpolicieseitheroverfitasingle dynamics model or rely on domain randomization without adaptation. Domain randomization of the dynamics parameters (8) is a powerful tool, but it forces fully Markovian (non-adaptive) policies to be conservative. Under domain randomization, the policy is incentivized to take conservative actions, for example, in a state/observation that is critical for some of the quadrotors (for example, due to thrust or angular acceleration limitations), the policy would have to take the action that saves these quadrotors, even if the current platform is agile enough to take the optimal action to continue the task.

In addition to overfitting a particular system model, in quadrotor racing, it has become standard to also overfit to a particular trajectory (such as a certain racetrack) (9,10). This trend limits broad adoption of these methods for real-world use cases because even just changing the environment requires a full retraining of the policy.

Humans, unlike these methods, which need to be retrained from scratch for each particular platform and/or application, can adapt few-shot to new systems. An illustrative example is driving cars (see Figure 1A and Movie S1). Initially, humans require extensive training to be able to control a car smoothly and robustly. But when they are driving a new, unseen car, they can adapt quickly. The steering, brake, and accelerator response might be quite different from the ones they have experienced before, but they usually only require a handful of tries to adapt.

With this work, we aim to devise a control policy that can adapt to unseen system dynamics using only minimal data, similar to humans. We are inspired by the recent progress on foundation models in the vision (11) and language domains (12). The two main premises of foundation models are:

- 1. Broad Distribution: Foundation models are trained on such a broad distribution of data that most expected queries at deployment time will be in-distribution with respect to the training data distribution.
- 2. In-Context Learning: Foundation models take causal sequences as input, facilitating incontext learning.

Therefore, the goal is that our policy can quickly adapt to novel systems by interacting with them and using the context/sequence of high-frequency interactions to reason about the dynamics. This can also be seen as emergent implicit system identification. The objective is to control the quadrotor, that is, based on the observations, output low-level motor commands that achieve an objective (such as controlling the position). Since the optimal outputs are dependent on the system dynamics, the (recurrent) policy has to learn to implicitly identify the unobserved/latent dynamics variables on the fly (figuratively and literally).

We refer to this as emergent implicit system identification because it only needs to infer the parts of the quadrotor dynamics parameters that are relevant to the input/output behavior of the system. These relevant parts can, for example, be ratios like thrust-to-weight ratio, torque-to-inertia

ratio, but also aggregates of motor delays, thrust curves, and so on. We never train any neural network to explicitly reconstruct system parameters. The only training objective is performing well in terms of the reward function. This fulfills the premise 2) of foundation models.

The premise 1) of foundation models, training on such a broad distribution that all conceivable inferencequeriesarein-distribution,iscoveredbydesigningaverybroaddistributionoverdynamics parameters that covers virtually all realistic quadrotors. This distribution is then used to sample quadrotors to train the aforementioned adaptive policy with emergent system identification.

The six main research questions are:

- 1. Feasibility: Can a recurrent, end-to-end neural network policy express the described behavior?
- 2. What size (number of parameters) does the recurrent neural network policy require to express this behavior? Can it run in hard real-time at high frequencies when deployed on small microcontrollers?
- 3. What context window is feasible? Recurrent neural networks are notoriously hard to train for sequences longer than 100 − 200 steps. Will the policy forget the system dynamics after a short time?
- 4. Doesthepolicygeneralizetounseenquadrotorsthatarein-distributionandout-of-distribution?
- 5. Howmuchtimeisrequiredfromactivatingthepolicyuntilithasgatheredenoughinformation to stably control the quadrotor? Is this feasible mid-flight, or would the quadrotor crash before the policy has identified the system properly?
- 6. Is there a trade-off between agility and adaptability?

We tackle the question of feasibility 1) by devising a method to train such a foundation policy for quadrotor control, implementing it, and testing it on a range of real-world quadrotors.

We tackle the size and inference speed question 2) by studying the scaling laws (13) in the student policy and by deploying the final foundation policy directly onto the microcontrollers of even the tiniest quadrotors.

We tackle the context window size question 3) by testing the context window extrapolation beyond the trained size.

We tackle the generalization question 4) by testing the policy on 9 unseen but in-distribution (in terms of thrust-to-weight ratio, torque-to-inertia ratio, motor delays, and thrust curves) quadrotors in the real world. We also study the out-of-distribution performance by testing the foundation policy (a) on a quadrotor with a flexible frame (making it a total of 10 real quadrotors), (b) by installing four different propellers (2- and 3-blade), (c) by hitting it with a tool during flight, and (d) by testing it with a quadrotor that has thrust-to-weight ratio > 2× higher than the highest one experienced during training.

We tackle the question of the number of timesteps required to infer the system dynamics 5) by studying activation response trajectories, where the policy is activated in mid-air. Here, the policy needs to probe the system and infer the dynamics of it rapidly to restore or maintain stable flight.

We tackle question 6) about the agility-adaptability trade-off by testing the resulting foundation policy on the task of tracking trajectories from quasi-static to highly dynamic.

Answering these research questions, we provide the following five main contributions:

- 1. RAPTOR (Real-time Adaptive Policy Through Online Reasoning): A method to train an end-to-end foundation policy for quadrotor control that can adapt to virtually any quadrotor platform zero-shot. This method consists of:

- • Design of a distribution over dynamics parameters that resemble physically plausible quadrotors.
- • Our proposed distillation method called Meta-Imitation Learning that condenses the behavior of 1000 Markovian teacher policies into a single adaptive/non-Markovian student policy.
- • A formal derivation of the design of the RAPTOR architecture.

- 2. We contribute a highly efficient, open-source implementation of the aforementioned method that allows to reproduce our results even with resource-constrained, consumer-grade hardware.
- 3. We study the scaling laws of the Meta-Imitation Learning process.
- 4. We conduct extensive experiments (indoor and outdoor) across 10 quadrotor platforms with different flight controller setups to validate that the foundation policy resulting from our proposed method answers the stated research questions and attains the stated goals.
- 5. We provide robust and simple means to use our resulting foundation policy for quadrotor control in different flight controller firmwares as well as simulation environments. This facilitates the reproducibility of our results and simplifies its usage as a baseline in future works of the community.

Although there have been many works on neural-network-based quadrotor control, most rely on lower-level controllers by, for example, outputting collective thrust and body-rate (CTBR) setpoints and, hence, are not fully end-to-end (14,4,5,15,16,17). But recently there have also been works investigating full neural-network-based end-to-end control (18, 19, 20, 21, 22). Although these approaches have attained comparable performance to classical control schemes, the control policies are each highly optimized for a single quadrotor. Changing the quadrotor requires system identification to adjust the dynamics parameters of the simulator and a full retraining of the policy. This shortcoming is being tackled by the community right now, with works that investigate better adaptability and/or generalization of neural-network policies to multiple quadrotors. In particular, (23) and (6) are the most related works to our approach.

In (6), the authors train a single neural-network policy that can be deployed onto two different quadrotors with thrust-to-weight ratios of ≈ 5.8 and ≈ 11.0, respectively. The authors demonstrate impressive agility for racing through gates. The main difference to our approach is that their policy is Markovian/stateless, whereas ours is adaptive.

Compared to (6), (23) is more related to our approach because the method intends to train a policy that can adapt to different quadrotors. In (23), the authors show deployment of their adaptive policytotworelativelysimilarquadrotorswiththrust-to-weightratiosof3.23and3.62,respectively. The biggest differences to our work are that their approach is not end-to-end. A high-level controller that outputs collective thrusts and body-rates (CTBR) is required. Their adaptive policy receives these CTBR setpoints as an input and is not concerned with rotational mechanics. Our foundation

policy is a full position controller and hence, in contrast to (23), also understands the tilt required to build up linear velocity and execute translations as well as the angular velocities required to execute a particular tilt. Our policy covers these major non-linear transfer functions whereas their policy only covers the angular rate (and thrust control) that is commonly implemented by a simple PD controller. Additionally, our policy architecture is simpler because it does not require training two encoders that map into the same latent space. Furthermore, our policy is vastly lighter, requiring only 2084 parameters whereas theirs requires 114872 parameters (55× larger), even though our policy covers more complex behavior. Because their policy is so computationally intensive, we cannot run it on any of the 10 quadrotors we are using for testing without modifying the hardware to include a more powerful inference computer. Finally, the authors of (23) do not publish their full training code, making it hard to exactly replicate their results. In contrast, we publish the full training and inference code in an easy and future-proof way. Additionally, readers can interact with the foundation policy through the web app at https://raptor.rl.tools.

Beyond quadrotor control, distilling the behavior of a privileged teacher into a partially observable student has become increasingly popular for robotic control tasks. In (24), this idea is referred to as “Learning by Cheating”, and a policy for driving cars is distilled from a teacher that is based on imitation learning with dense states from expert demonstrations into a student that only receives visual inputs. Compared to our approach, the inference is not performed by integrating information over time, but by extracting the remaining information after a lossy projection (ego-view). In (25) and (26), the authors distill privileged teachers that can observe details about the terrain into student policies that only receive proprioceptive observations. Like in (23), the latter uses an environment encoder and shares the control head between teacher and student. Like in our work, the students are sequence models. Although distilling a privileged teacher into a partially observable student appears like a simple concept at a high level, there are many nuances and design decisions, many of which have been studied recently in (27). The authors show the effectiveness of a GRU-based adaptive policy and thoroughly ablate many important aspects, but only demonstrate it using a cartpole, which is a relatively simple system compared to the quadrupeds and quadrotors used in this and the other referenced works. In contrast to all other works, we do not restrict our method to a single teacher. This circumvents well-known challenges in multi-task RL, where “negative transfer” is often observed (28,29), and additionally makes the pre-training stage embarrassingly parallel, which suits modern hardware well.

#### Results

Our results show that our method leads to a robust and highly adaptable foundation policy for quadrotor control. In the following, we first discuss insights from the training (pre- and posttraining) using our method, as well as results from deploying the single foundation policy to multiple real-world platforms under different conditions.

##### Training

In the following, we describe the training results. The methods used to attain these results are described in the Materials and Methods section. As described in the Materials and Methods section and Figure 1B, our training method separates into a pre-training phase and a post-training phase.

###### Pre-Training

In the pre-training phase, we train 1000 teacher policies that are each specialized for a single quadrotor. The quadrotors differ in their dynamics parameters, which are sampled from the distribution described in the Domain Randomization subsection.

We find that the pre-training method described in the Pre-Training subsection of the Materials and Methods section is remarkably robust and that all 1000 RL training runs reliably converge to good policies, all of which can be used for the downstream Meta-Imitation Learning. This is surprising because RL training loops are known to be unstable and hence it is common to run the training with numerous seeds and then cherry-pick the best final policy (30,31,32,33,34,35).

In contrast, we can use the same initial seed in all 1000 cases, and we do not need to cherry-pick a different seed for each quadrotor. Note that our training runs are deterministic, that is, a training run with the same seed always gives identical results (on the same computer). We attribute this stability to a combination of three main factors:

- 1. Overparameterization: Since we do not need to deploy the teacher policies onto constrained hardware, we can use much larger (≈ 55×) neural networks. This overparameterization is known to improve the loss landscape and stabilize training (36).
- 2. RewardFunction:Wetunedtherewardfunctionforreliabletraining,particularlythesurvival bonus and the termination penalty.
- 3. Off-Policy RL: We use an off-policy RL algorithm (SAC) because our experience matches the literature in that on-policy methods like PPO are usually more unstable and prone to local minima (37). We find off-policy methods to be particularly robust when the replay buffer retains all interaction steps and when combined with the previous two points.

If these conditions are met, it is just a matter of training long enough to see all training runs converge to a good policy (see Figure 2A). We also release the supplementary dataset Data S1 of 1000 dynamics parameters and the 1000 trained policies for each of them for further study.

The aggregated learning curve resulting from the pre-training phase can be seen in Figure 2A. We use the episode length as the metric here because it is more robust to the variation in quadrotor dynamics than the return. More agile quadrotors, for example, achieve much higher returns than less agile quadrotors, even if both are controlled by their respective optimal policy (with respect to the same reward function).

Wefindthatthepoliciesalreadyachievegoodbehaviorafteronly100000stepsoftraining,which is signified by the majority of policies reaching episode lengths of 400 steps or more. We observe that the main flight capabilities are attained in the first 100000 steps, and that subsequent steps refine the behavior when starting in challenging initial conditions (large tilt, large linear velocity, position close to the termination boundary, etc.) as shown in the episode lengths converging to the maximum limit. We also observe that, in the later stages of the pre-training, the steady-state performance (which is not well expressed in the episode length) is also still improving.

Since, in contrast to inference, the pre-training only incurs a one-time computational cost, we decide to train each teacher policy for 1 M steps. Each training run takes 31 min on a single core (consumer laptop, AMD Ryzen 9 7945HX, 16 cores). Hence, the full pre-training takes about 34 h on a single consumer laptop. Please refer to the Pre-Training subsection in the Materials and Methods section for details on why and how the pre-training can be parallelized and sped up.

(A) Learning Curve: Pre-Training

| | | | | |
|---|---|---|---|---|
|Maximum Episode Length<br><br>Episode Length<br><br>Worst 5 runs| | | | |
| | | | | |

500

EpisodeLength[#steps]

400

300

200

(500)

100

0

0.0 0.2 0.4 0.6 0.8 1.0 Training Step 1e6

(C) Pareto Frontier: Number of Teachers

- 471

- 472

- 473

- 474

- 475

- 476

1000

EpisodeLength[#steps]

125 250 500

64

32

Number of Teachers

Chosen

16

0 200 400 600 800 1000 Number of Teachers

(B) Learning Curve: Meta-Imitation Learning

500

EpisodeLength[#steps]

400

ARPL

300

Crazyflie

Flightmare

Large

200

MRS

Soft

100

x500

0 25 50 75 100 125 150

0

0 200 400 600 800 1000 Epoch

(D) Pareto Frontier: Model Size

32 48 64

480

EpisodeLength[#steps]

16

460

8

440

420

Hidden Dimensionality

400

Chosen

4

0 10000 20000 30000 40000 50000 Inference Compute [FLOPS]

Figure2:TrainingResults.(A)showsthepre-traininglearningcurve,(B)showsthemeta-imitation learning curve where the policy is evaluated using a validation set of 7 quadrotors that are not seen during training, (C) shows the Pareto frontier between performance and number of teachers, and (D) shows the Pareto frontier between performance and student/foundation policy size.

###### Meta-Imitation Learning

During the Meta-Imitation Learning phase, we observe that the student quickly learns to imitate any of the 1000 teachers. In Figure 2B, we plot the test performance of the foundation policy when controlling 7 unseen quadrotors in simulation. The set of 7 quadrotors consists of 5 quadrotors listed in Figure 4 that we deploy the foundation policy to and that we have accurate system parameters for (which is not the case for the remaining quadrotors in that table). Furthermore, we include two more quadrotors (”MRS” and ”Large”) that we have accurate system parameters for (from (38) and (39), respectively).

None of these test-set quadrotors appear in the 1000 pre-training quadrotors. We observe that the acquisition of good flying behavior follows a similar trajectory as a function of the epoch. For most quadrotors, the foundation policy achieves good performance early, but for the ”Flightmare” and especially the ”Large” model, we see continued improvement by training for longer. Eventually, after about 1000 epochs, we observe convergence and good performance on all 7 platforms, which span a large range of quadrotor dynamics, from agile to non-agile, lightweight to heavy, and more.

In Figure 2C, we study the performance of the resulting foundation policy when using the RAPTOR framework with different numbers of pre-training teachers/quadrotors. Here, the aggregate performance is shown across all 7 test quadrotors, and we observe that, even for a low number of teachers, the foundation policy is able to stabilize/control its position from various and challenging initial states without crashing.

As mentioned before, the episode length is an imperfect metric for the full performance of the policy, but, nevertheless, it is more suitable than the return, which strongly varies in scale, even just between the 7 test-set quadrotors. With a training time of 1.9 h (same AMD Ryzen 9 7945HX laptop), Meta-Imitation Learning is vastly less computationally intensive than the pre-training (1.9 h vs. 1000 × 31 min).

The training part of the RAPTOR framework only incurs a one-time cost compared to the deployment part, which is more resource-constrained and hence more sensitive computationally. Hence, we decide to employ all 1000 teachers in the main configuration of the RAPTOR framework.

Furthermore, and with the aforementioned resource constraints in mind, we also study the scaling behavior in the model size. In Figure 2D, we can see the Pareto frontier between inference compute in terms of Floating Point Operations (FLOPs) and performance in terms of episode length. Since, in this case, a larger model size actually entails continued computational costs during deployment, we chose a relatively small model with a hidden dimensionality of 16.

This small size allows the deployment to even the tiniest microcontrollers. Even on the most resource-constrained quadrotors, the resulting foundation policy requires < 10% of the available computational power, leaving plenty of capacity for state-estimation, communication, and other duties of the flight controller.

Hence, going forward (and in Figure 2A/B), we set the number of teachers to 1000 and the size of the hidden dimension in the policy to 16.

##### Emergent System Identification

Toanswerthestatedresearchquestions,wealsostudythebehaviorofthefoundationpolicyresulting from Meta-Imitation Learning. We find that it indeed exhibits in-context learning as can be seen in Figure 3. Here we start a quadrotor in a state where it is displaced by 2 m from the target position in 𝑥 and 𝑦 as well as pitched backwards by 90◦ (no linear or angular velocity). First of all, we can see that the policy successfully manages to recover from this initial state and to reduce the distances towards the target state in position, orientation, linear and angular velocity.

Additionally, we plot the trajectory of the hidden state and investigate if it learns something about the dynamics of the quadrotor it is interacting with. We know the ground-truth dynamics parameters of the 1000 quadrotors used for pre-training, hence we can train a linear probe (40) to predict, for example, the thrust-to-weight ratio. Linear probing has become a standard test to evaluate if foundation models learn good representations (11,41,42).

As can be seen from the regression plot in Figure 3, just a linear probe can predict the thrustto-weight ratio very well. For this experiment, we collect 100 new episodes (neither seen during Pre-Training nor Meta-Imitation Learning) from random initial states for each of the 1000 sampled quadrotors. We use an 80%-20% train-test split and the linear model achieves a Mean-Squared Error (MSE) of 0.047 and an 𝑅2 of 0.949, substantially reducing the a priori uncertainty about the thrust-to-weight ratio. This shows that Meta-Imitation Learning leads to emergent implicit system identification in the latent space of the foundation policy.

Although quickly going into the right range, we can also see that the estimate is improving over time, showing the in-context learning of the policy.

[Figure 21]

[Figure 22]

[Figure 23]

[Figure 24]

[Figure 25]

[Figure 26]

[Figure 27]

[Figure 28]

[Figure 29]

[Figure 30]

[Figure 31]

[Figure 32]

[Figure 33]

[Figure 34]

[Figure 35]

[Figure 36]

[Figure 37]

[Figure 38]

[Figure 39]

[Figure 40]

pitch: −90◦ position: (2m,2m,0m)

1.0

Position

Error[relative]

Orientation

Linear Velocity

0.5

Angular Velocity

0.0

15

| |[Figure 41]|[Figure 42]<br><br>| | | | |
|---|---|---|---|---|---|---|
| | | | | | | |
| | | | | | | |
| | | | | | | |

HiddenDimension

10

5

0

0 100 200 300 400 500

1000×

Emergent System Identification: Thrust-to-Weight

[Figure 43]

[Figure 44]

4.5

t2w( ) t2w( ) t2w( ) t2w( )

[Figure 45]

4.0

[Figure 46]

X=

y=

Predicted

3.5

[Figure 47]

[Figure 48]

3.0

Predictions

2.5

Mean prediction ± y ~ X·w Identity

Linear Regression:

2.0

2.0 2.5 3.0 3.5 4.0 4.5 Ground Truth

ThrusttoWeightRatio

| | | | | |
|---|---|---|---|---|
|Predicted<br><br>Ground Truth| | | | |
| | | | | |

4

2

0

0 100 200 300 400 500 Time Step (@ 100 Hz)

###### Figure 3: Inference Results. Here we show a recovery1 of a simulated quadrotor from an adverse initialconditionusingthetrainedfoundationpolicy.Weshowthelatentstateofthepolicythroughout the trajectory and test if it performs emergent/implicit system identification by training a linear probe.

[Figure 49]

[Figure 50]

[Figure 51]

[Figure 52]

[Figure 53]

[Figure 54]

[Figure 55]

[Figure 56]

[Figure 57]

[Figure 58]

[Figure 59]

[Figure 60]

Hummingbird

M5StampFly

Crazyflie Brushless

Meteor75 Pro

SavageBee Pusher

Crazyflie

Pavo20

ARPL Soft x500 Gazebo Flightmare

Firmware Betaflight Crazyflie M5StampFly Crazyflie Betaflight PX4 Flightmare Motors brushless brushed brushless #Blades 3 2 4 2 3 2 2 2/3 3 2 2 2 Battery 1S 2S 4S/6S 4S - Weight 31.9 g 35.2 g 38 g 42.3 g 40.4 g 91.8 g 155.4 g 801 g 948 g ˜1.2-2.4 kg 1.5k kg 730 g Thrust-to-weight ? ∼ 1.75 ? ? ? ? ? ∼ 3.9 ∼ 3.3 ∼ 3.2 ∼ 2.3 ∼ 12 Wheel-base 65 mm 80 mm 65 mm 100 mm 80.8 mm 90 mm 120 mm 250 mm 441 mm 500 mm 286 mm 340 mm Configuration puller pusher puller State-estimator Mahony EKF Madgwick EKF Mahony EKF GT Real ✓ ✓ ✓ ✓ ✓ ✓ ✓ ✓ ✓ ✓ ✗ ✗ Prop-guards ✓ ✗ ✓ ✓ ✓ ✓ ✓ ✗ ✓ ✗ ✗ ✓ Symmetric ✓ ✓ ✓ ✓ ✓ ✓ ✓ ✗ ✗ ✓ ✗ ✓ Flexible ✗ ✗ ✓ ✗ ✗ ✗ ✗ ✗ ✓ ✗ ✗ ✗ Price $99 $240 $49 $480 $105 $125 $399 not COTS not COTS $500 free free

- Figure 4: Test Quadrotors. A diverse set of 10 real and 2 simulated quadrotors that we use in the experiments.

##### Deployment

To show the robustness and adaptability of the foundation policy that results from applying the RAPTOR framework, we deploy the foundation policy onto 10 different real quadrotors and 2 different simulators (see Figure 4) showing Simulation-to-Reality (Sim2Real) and Simulation-toSimulation (Sim2Sim) transfer. We aim to strain the adaptation capabilities of the foundation policy as much as possible by testing across a wide range of parameters:

- 1. A quantitatively wide range of parameters: weight (31.9 g - 2.4 kg), size (65 mm - 500 mm), and thrust-to-weight (≈ 1.75 - 12).
- 2. Aqualitativelydiversesetoffeatures:flightcontroller(PX4,Betaflight,Crazyflie,M5StampFly), state estimator (EKF, Mahony, Madgwick), motor type (brushed and brushless), flexible frame, and mixing two- and three-blade propellers.

Many of these quantities are (far) out-of-distribution, like a thrust-to-weight ratio of 12 (≤ 5 in training), a flexible frame (only rigid during training), and observations from a state estimator (Ground Truth during training).

This shows that our proposed RAPTOR framework actually produces a policy that not only generalizes to quadrotors that are in the training distribution (see Domain Randomization subsection) but also out-of-distribution (OOD).

Contrary to popular belief, and supporting the results in (7), we find that the simulation-toreality transfer of end-to-end neural network policies is actually not hampered by the mismatch in the dynamics model, especially because the parameters can be relatively easily and accurately determined using (39). We find that qualitative differences matter much more. Especially for stateful policies (like the RNN used in the RAPTOR foundation policy), implementation details in the firmware that lead to delays and other artifacts have a strong influence on the simulation-to-reality deployment.

We find that the foundation policy works robustly on all platforms, but we also observe lowfrequency z-axis oscillations in some of the non-EKF-based quadrotors. In the case of the Mahony (43) and Madgwick (44) filters, only the orientation is estimated by the filter and the velocity is directly fed from the motion capture system.

We hypothesize that this leads to the z-axis oscillations due to communication delays. We can reproduce the z-axis oscillations in simulation across quadrotors of different dynamics parameters by inducing a linear velocity delay of 10 − 30 ms.

Intuitively, it makes sense that the foundation policy heavily relies on changes in the linear velocity to estimate the acceleration that is caused by the series of actions it produced previously. The policy can use these observations to estimate dynamics parameters like the thrust-to-weight ratio. Please refer to the Supplementary Materials (45) for the mitigation we implemented for this.

###### Trajectory Tracking

Besides position control (supporting ”goto” workflows), trajectory tracking is an important task for real-world applications. Despite only training with random, relatively slow reference trajectories, we find that the resulting foundation policy is able to track figure-eight trajectories of varying agility well.

Figure 5 and Movie S2 show trajectory tracking of a Lissajous-based figure-eight trajectory at different intervals. We test tracking the 10 s and 5.5 s trajectories using the foundation policy on all 12 quadrotors. Each of the shown trajectories constitutes 5 consecutive full loops with an initial linear ramp-up time of 1 s (from hovering).

Figure 5 shows consistent real-world trajectory-tracking performance across repetitions. The Root Mean Square Error (RMSE) ranges between 0.07 m and 0.19 m (mean: 0.11 m, standard deviation: 0.04 m) for the 10 s figure-eight trajectory and between 0.17 m and 0.29 m (mean: 0.20 m, standard deviation: 0.04 m) for the 5.5 s figure-eight trajectory.

The tracking performance is in line with state-of-the-art policies (without trajectory lookahead, like the foundation policy) that are trained for a single quadrotor (7). The dedicated policy that has been specifically trained for deployment on a Crazyflie in (7) reaches an RMSE tracking error of 0.17 m and 0.15 m (with and without the z-axis) for the identical 5.5 s figure-eight trajectory. The foundation policy resulting from the RAPTOR framework reaches 0.19 m and 0.19 m, respectively, on the same platform. Although the tracking error of the foundation policy is slightly elevated compared to the dedicated policy, through online adaptation, the foundation policy can attain a similar performance on a plethora of other quadrotors as well. Note that our policy still performs better than the two other neural-network-based baselines evaluated in (7) which attain 0.23 m / 0.21 m (18) and 0.25 m / 0.24 m (37), respectively.

From the RMSE difference between including the z-axis and excluding it, we can see that for all real quadrotors, the tracking error is mostly in the x-y plane. This shows that the foundation policy successfully adapts to the different thrust-to-weight ratios, battery levels, and other conditions, and adaptively cancels out the z-error.

The third cluster of trajectories in Figure 5 shows the fastest trajectory that we tested for each quadrotor. This does not necessarily mean that this is the fastest trajectory supported by the foundation policy, because, to avoid crashes, we did not push all quadrotors (especially the larger ones) beyond their limits. For the Hummingbird, Crazyflie, M5StampFly, Crazyflie Brushless, and Meteor75 Pro, we did push them beyond their (or the foundation policy’s) limits and find that the

Interval: 10 s

| | | | |
|---|---|---|---|
|Crazyflie| | | |
| | | | |
| | | | |
|Pavo20| | | |
| | | | |
| | | | |
|x500| | | |
| | | | |
| | | | |

1.2

0.5

|[Figure 61]| |
|---|---|
| | |
| | |
| | |
| | |
| | |

Hummingbird

M5StampFly

Brushless

Crazyflie

Crazyflie

y[m]

0.0

1.0

0.5

0.8

0.5

speed[m/s]

Meteor75Pro

Savagebee

Pusher

Pavo20

y[m]

ARPL

0.0

0.6

0.5

0.4

0.5

Simulation

Flightmare

Gazebo

0.2

y[m]

x500

0.0

Soft

0.5

0.0

1 0 1 x [m]

1 0 1

1 0 1 x [m]

1 0 1 x [m]

x [m]

Interval: 5.5 s

| | | | |
|---|---|---|---|
|Crazyflie| | | |
| | | | |
| | | | |
| | | | |
|Pavo20| | | |
| | | | |
|x500| | | |
| | | | |
| | | | |
| | | | |

0.5

|[Figure 62]| |
|---|---|
| | |
| | |
| | |
| | |

Hummingbird

M5StampFly

Brushless

Crazyflie

Crazyflie

y[m]

2.0

0.0

0.5

1.5

0.5

speed[m/s]

Meteor75Pro

Savagebee

Pusher

Pavo20

y[m]

ARPL

0.0

1.0

0.5

0.5

Simulation

0.5

Flightmare

Gazebo

y[m]

x500

0.0

Soft

0.5

0.0

1 0 1 x [m]

1 0 1

1 0 1 x [m]

1 0 1 x [m]

x [m]

Interval: Fastest

| | | | |
|---|---|---|---|
| | | | |
|Crazyflie| | | |
| | | | |
| | | | |
|Pavo20| | | |
| | | | |
|x500| | | |
| | | | |
| | | | |
| | | | |

0.5

|[Figure 63]| |
|---|---|
| | |
| | |
| | |
| | |

Hummingbird

M5StampFly

Brushless

Crazyflie

Crazyflie

y[m]

0.0

- 0
- 1
- 2
- 3
- 4

0.5

0.5

speed[m/s]

Meteor75Pro

Savagebee

Pusher

Pavo20

y[m]

ARPL

0.0

0.5

0.5

Simulation

Flightmare

Gazebo

y[m]

0.0

Soft

0.5

1 0 1 x [m]

1 0 1

1 0 1 x [m]

1 0 1 x [m]

x [m]

|Interval Metric<br><br>|Hummingbird<br><br>Crazyflie<br><br>M5StampFly<br><br>Crazyflie Brushless<br><br>Meteor75 Pro<br><br>Pavo20<br><br>Savagebee Pusher<br><br>ARPL Soft x500 Flightmare Gazebo|
|---|---|
|RMSE [m] 10 s RMSE w/o z [m]<br><br>Max velocity [m/s] RMSE [m]<br><br>5.50 s RMSE w/o z [m]<br><br>Max velocity [m/s] Interval [s] RMSE [m] RMSE w/o z [m]<br><br>Fastest<br><br>Max velocity [m/s]|0.08 0.12 0.08 0.08 0.10 0.19 0.07 0.17 0.09 0.11 0.32 0.14<br><br>0.08 0.12 0.07 0.08 0.08 0.19 0.07 0.16 0.09 0.10 0.22 0.13<br><br>1.02 1.20 1.03 1.01 1.11 1.06 1.10 1.06 1.09 1.05 1.04 0.96<br><br>0.18 0.19 0.29 0.17 0.19 0.21 0.18 0.22 0.26 0.21 0.35 0.19 0.17 0.19 0.28 0.16 0.17 0.21 0.18 0.20 0.26 0.21 0.23 0.18<br><br>2.06 2.06 2.26 1.97 2.03 1.97 2.11 1.96 2.24 1.95 1.98 1.62 4.5 3.5 3.5 3.0 4.5 4.5 4.5 4.0 4.5 4.5 3.5 4.5<br><br><br>0.27 0.37 0.59 0.50 0.23 0.26 0.24 0.22 0.34 0.27 0.40 0.22 0.27 0.32 0.54 0.38 0.22 0.26 0.24 0.20 0.33 0.26 0.31 0.20 2.99 3.55 3.16 4.47 2.57 2.62 2.70 1.96 2.97 2.48 4.72 2.19<br><br>|

- Figure 5: Trajectory Tracking Results. Trajectory1 tracking results of the 10 real and 2 simulation quadrotors.

1

shown trajectories are the most agile ones that can still be tracked with decent accuracy. When pushing, for example, the Hummingbird or the Meteor75 Pro further, they still remain stable, but they overshoot so much that the figure-eight becomes barely recognizable.

Basedonthisobservation,wehypothesizethatforagiletrajectorytracking,thefoundationpolicy is mainly bottlenecked by the lack of trajectory lookahead in the observations. This analysis is also based on prior lookahead-free works (7) and recent works ablating the inclusion of lookahead (46).

As can be seen from the maximum velocity measurements, we push the foundation policy up to 3 − 4 m/s in these indoor experiments.

###### Outdoor Tests

Additionally, we conduct outdoor tests using the x500 platform. During these tests, there was a strong wind of about 7 m/s, gusting up to 10 m/s. We test trajectories resulting in linear velocities of up to 10 m/s over ground and more than 15 m/s relative to the wind. We did not see signs of instability at these speeds, and will investigate larger speeds in future work.

Furthermore, we equip the quadrotor with up to 1.2 kg of payload (water-filled bottles), which, including the battery, is slightly above the specified maximum payload capability of the platform of 1.5 kg. This setup leads to a take-off weight of 2.4 kg, and the foundation policy is still able to control the quadrotor when hovering. With a payload of a single bottle (600 g), we can still track trajectories, as can be seen in the supplementary Movie S3.

###### Disturbances

We test a variety of disturbances, including hitting the quadrotors with a tool, resting the tool on top of the quadrotor while flying, as well as wind disturbances from a strong fan. Examples of these disturbances can be seen in Figure 6 and Movies S4 and S5. In Figure 6D and Movie S4, we strongly hit the quadrotor (that starts out hovering) from the bottom, leading to a strong tilt in excess of 90◦. While losing altitude, the foundation policy still manages to recover the quadrotor. In Figure 6E, we rest the tool on top of a flying quadrotor, and the foundation policy quickly adapts to the added weight and does not incur a steady-state altitude deficit.

Additionally, we also test swapping out 1, 2, and 3 propellers with random three-blade ones (the original ones are two-blade) and find that, in any of these configurations, the foundation policy still stably controls the vehicle and is even able to track trajectories (see Figure 6F and Movie S6). Note that the distribution of quadrotors described in the Domain Randomization subsection covers only quadrotors with identical thrust curves for all four motors/propellers. Hence, neither the teacher policiesnorthefoundationpolicyhaseverexperienceddifferingthrustcurvesonthesamequadrotor. Yet, we find that the foundation policy can generalize zero-shot outside of this distribution, and control the quadrotor well.

In the absence of disturbances, we find that the foundation policy yields a remarkably repeatable performance, as can be seen from the trajectories in Figure 5, which show 5 consecutive full loops each. This also answers the posed research question about the trajectory length generalization of the foundation policy. During Meta-Imitation Learning, we train the policy with sequences of 500 steps, corresponding to 5 s of flight time. During inference, we test the foundation policy with 5 consecutive iterations of, for example, a 10 s, amounting to a trajectory length of 50 s. This shows a 10× context window size extrapolation.

[Figure 64]

- A

[Figure 65]

[Figure 66]

- B C

Manual 4.5 m/s Foundation Policy

3 loops

[Figure 67]

[Figure 68]

D E

[Figure 69]

F

- Figure 6: RAPTOR Policy in Different Situations. (A): The foundation policy is activated in midair, starting with a linear velocity of 4.5 m/s. (B): Crazyflie Brushless tracking an agile trajectory. (C): Long exposure photo of three consecutive loops of the Crazyflie Brushless trajectory. (D): The foundation policy recovers from being poked and tilting > 90◦. (E): A tool is rested onto the quadrotor flown by the foundation policy. (F): A quadrotor with four different propellers (2- and 3-blade) is tracking a trajectory using the foundation policy.

In practice, we did not notice any limits on how long the policy can be activated at a time. We fly until the battery is empty (several minutes) many times over. Hence, we believe the resulting foundation policy can generalize to arbitrary trajectory lengths without degrading performance, despite only being trained on fixed-size trajectories.

Additionally, in Figure 6C, we can see the precise repeatability through a long-exposure photo of three full loops. The deviations between loops are barely recognizable. Figure 6B shows a chronophotograph of the same trajectory with the lights on.

Furthermore, we also test the recovery from aggressive initial states. An example of this is shown in Figure 6A and Movie S7, where the quadrotor is accelerated to 4.5 m/s using manual control and then the foundation policy is activated in mid-air. The policy is activated using a push button on the transmitter, and its goal (through offsetting of the observations) is to hover at the position where it was activated.

When it is activated, the hidden state is reset and the policy has to adapt zero-shot, in minimal time, to save the quadrotor.

Note that all of the previously described experiments (and more) are included in the supplementary video material, where these agile maneuvers and disturbances can be observed in motion. In Movie S2, we also show flying 6 different quadrotors (Hummingbird, Crazyflie, M5StampFly, Crazyflie Brushless, SavageBee Pusher, ARPL) from Figure 4 with 4 different firmwares and 4 different communication protocols at the same time in a tight indoor space. We find that, despite the turbulent flow created by the other quadrotors that are flying close by, the foundation policy still manages to stably control each of the quadrotors. We also accidentally fly a SavageBee Pusher (155.4 g) and a Crazyflie Brushless (42.3 g) directly beneath a hovering ARPL platform (801 g), and find that the foundation policy manages to quickly adapt and adjust to/recover from the disturbance. Furthermore, Movie S8 contains yaw step-response tests.

###### Simulation

To further test the out-of-distribution generalization beyond the aforementioned real-world tests including flexible frame, mixed propellers, and context window extrapolation, we test simulationto-simulation transfer to the Flightmare simulator. This transfer is interesting, because the thrustto-weight ratio of its default quadrotor is ≈ 12 (see Figure 4) and hence > 2× the upper limit of 5 of our domain randomization range. We find that the z-error is substantial, but the foundation policy still controls it robustly and can track agile trajectories. This shows the remarkable robustness and out-of-distribution generalization of the foundation policy resulting from the RAPTOR method.

#### Discussion

In our extensive experimental evaluations, we find that our proposed RAPTOR framework produces a highly robust and versatile foundation policy that can control a broad range of quadrotors in a large variety of situations. Compared to state-of-the-art solutions for end-to-end quadrotor control, our method is able to adapt to a wide range of physical platforms without re-training, through in-context learning. Even though existing methods rely on overfitting a control policy for each platform, our method is able to approximately match their performance while providing the flexibility of zero-shot adaptation and being substantially more light-weight, computationally. This allows, for

example, deployment on platforms whose parameters have not yet been identified. Due to the minimal compute requirements of the tiny resulting policy, it can be deployed even on the smallest quadrotors. Hence, we believe that our experiments validate the design choices in the RAPTOR architecture.

Nevertheless, through experimentation in the real world, we find that there are many avenues for future research based on our proposed architecture, including the following 4 directions:

- 1. Simulation-to-reality gap in flight controller firmware implementations: We find that a large part of the simulation-to-reality gap comes from delays in the flight controller firmware and infrastructure around the foundation policy as well as the state estimation. We see potential for introducing more domain randomization to simulate delays that appear during deployment, as well as moving to a fully end-to-end architecture by cutting out the state estimation and directly feeding IMU data into the policy.
- 2. Over-reliance on linear velocity observations: We find that the foundation policy overindexes on the linear velocity observations to perform emergent system identification. In real-world deployments, there is usually a delay from the infrastructure (motion capture system) or other disturbing factors (such as drift in GPS). In future work, we believe this problem can be alleviated by adding more observation noise to the linear velocity observations and adding accelerometer measurements to the observation space.
- 3. Limited domain randomization range: Although our distribution over quadrotor dynamics already covers a vast range of quadrotors (and arguably >> 50% of quadrotors that are being used in the real world), our experiments showed that there are limits to the out-of-distribution generalization. We believe that the lower tracking performance on the Flightmare platform (thrust-to-weight ratio of ≈ 12 vs. ≤ 5 during training) can be alleviated by extending the domain randomization range because when limiting its thrust-to-weight ratio to 5, we find it to yield excellent tracking performance.
- 4. Trajectory tracking lookahead: We find that lookahead-free trajectory tracking is posing a limit and believe that integrating lookahead into the RAPTOR architecture can substantially improve the trajectory tracking performance.

#### Materials and Methods

We formulate the quadrotor control problem as a Bayes Adaptive Partially Observable Markov Decision Process (BAPOMDP) (47) defined by the tuple (S, S0, D, A, T, r, O, o, 𝛾, 𝚵). S is the set of states s = {p, q, v, 𝝎, a𝑡−1, 𝝎𝑚, fext} consisting of position, orientation, linear/angular velocity, previous action, motor states and a random external force, respectively. The previous action is included in the state because the reward function penalizes the change in action. S0 is the initial state distribution with position, orientation, linear/angular velocity uniformly sampled up to 10·𝑙arm, 90◦, 1 m/s, 1 rad/s, respectively. With a probability of 10%, the initial state is overwritten with the target state (all zeros). The random force fext resembles, for example, wind disturbances and is sampled from a zero-mean normal distribution with a standard deviation derived from the sampled dynamics parameters (see supplementary materials (45)). D is the termination relation that includes

all states outside 20·𝑙arm m, 2 m/s, 35 rad/s (position, linear/angular velocity respectively). A is the set of actions a = {𝜔sp0, 𝜔sp1, 𝜔sp2, 𝜔sp3} (individual motor commands). The transition probabilities T are defined as p(s𝑡+1|s𝑡, a𝑡, 𝚵) and implemented by the L2F simulator (7). The reward function is deterministic:

r(s𝑡, a𝑡, s𝑡+1) = −∥p∥2 − 0.2 · arccos(1 − |𝑞𝑧|) − ∥a𝑡 − a𝑡−1∥2 + 1.5 − 100 · 1[terminal(s𝑡+1)] (1)

We include the next state in the reward function to be able to inflict the termination penalty. The observation space O contains a subset of the state space o = {p, R(q), v, 𝝎, a𝑡−1}, occluding the motor states 𝝎𝒎 (not observable on most real-world platforms) and the external disturbance. 𝛾 = 0.99 is the discount factor and the domain parameters are collected in 𝚵 = {𝑚, 𝑙arm, 𝑐𝑓0, 𝑐𝑓1, 𝑐𝑓2, 𝑐𝑚, J = diag(𝐽𝑥𝑥, 𝐽𝑦𝑦, 𝐽𝑧𝑧),𝑇𝑚↑,𝑇𝑚↓} containing the mass, arm length, thrust-curve coefficients (zeroth, first and second order), moment coefficient, inertia matrix and rising/falling edge motor delays respectively. The difference between a BAPOMDP and a POMDP is that we can factor out the system parameters 𝚵 (which would have to be encoded into the state in a normal POMDP). This factorization allows us to implement the inductive bias that the parameters are only sampled once at the beginning of the episode and remain constant throughout.

Using this BAPOMDP framework, in the following, we provide a formal derivation of our method using a probabilistic graphical model (48). The full model is shown in Figure 7A. The goal is to model the decision-making at time 𝑡. At timestep 𝑡, 𝑡 previous observations and actions, as well

- as the current observation have been observed (shaded nodes). We explicitly place minimal assumptions on the policy that decides the previous actions, which shows by the previous actions being causally fully connected to all previous actions and observations. By causally fully connected, we

mean that an action at timestep 𝑡 might depend on observations o0, · · · , o𝑡 and actions a0, · · · , a𝑡−1. Hence, the only assumption is that the policy generating the previous trajectory is causal.

Since we want to maximize the expected discounted return (sum of rewards), we model the

probability of some action a being the optimal action a𝑡∗ := a. The optimal action is independent of previous states (and all other past random variables) given the current state s𝑡 and the dynamics parameters 𝚵:

a𝑡 ⊥⊥ s0, . . . , s𝑡−1 | s𝑡, 𝚵 (2) Due to the forward-looking nature of maximizing the discounted future returns, for completeness, we assume that future actions are also optimal. In our proposed Meta-Imitation Learning method, this distribution over the optimal action a𝑡∗ is approximated by a teacher policy that is trained using RL. In our method, we train 1000 teacher policies for each of the 1000 randomly sampled quadrotors/dynamics parameters 𝚵. This fits into the formal model in Figure 7A because the practical, finite number of dynamics parameters/teacher policies can be viewed as a Monte Carlo approximation for the mixture model, where a unified teacher is conditioned on 𝚵.

Since we want to train a foundation policy that can adapt to any realistic quadrotor and does not require knowledge of identified system parameters, and due to the motor states being unobservable on most quadrotor platforms, we can observe neither of the two direct ancestors s𝑡 and 𝚵 of the optimal action.

Using d-Separation (49), an algorithm to prove conditional independencies in probabilistic graphical models, we can show that not observing s𝑡 and 𝚵 makes the distribution over the optimal action a𝑡∗ dependent on other variables that could carry information about them. The most direct example is o𝑡. Since o𝑡 is derived from s𝑡, it can carry information about s𝑡 and in our case it carries

aπt

aπt Student

DKL a∗t ∥aπt

min

θ

...

...

a∗t

a∗t Teacher

at−1

at+1

a0

...

...

ot−1

ot+1

o0

ot

...

...

rt−1

rt+1

r0

rt

...

...

st−1

st+1

s0

st

sT

Ξ

###### A B C

Input/output Weights (frozen during inference) Latent space

- 1
- 2

quadraticthrustcurve

2

action [RPM setpoint]

0

|p R(q) v ω at-1|
|---|

- 1
- 2
- 3
- 4

|RPM|
|---|

Dense

GRU Dense

motor delay

4

observation [acceleration]

0

22x1 16x1

16x1

0 1 2 3 4 5 6 7 timestep

4x1

- Figure 7: (A): A probabilistic graphical model (Bayesian1 Network) of the dynamics and control of a random quadrotor. This formal model allows us to derive the RAPTOR architecture from probabilistic principles. (B): Foundation policy network architecture. (C): Illustration of inferring dynamics parameters by reasoning about the observed input/output behavior of the system.

almost all the information about the state, apart from the motor speeds. Hence, when o𝑡 is observed, this changes the distribution over the optimal action a𝑡∗. The same argument holds for o𝑡−1 and earlier observations because, for example, o𝑡−1 carries information about s𝑡−1 and s𝑡−1 (in combination with the observable a𝑡−1) carries all the information to infer the distribution over s𝑡. This is because s𝑡−1, a𝑡−1, 𝑟𝑡−1, and 𝚵 form the causal Markov blanket (49) for s𝑡. For the causal Markov blanket, random variables that lie in the future are removed. Therefore, using the d-Separation rules, we can see that the distribution over the optimal action a𝑡∗ is dependent on all previous observations and actions. There is no set of observable variables that could form a Markov blanket and shield this dependency. This motivates our design decision that the foundation policy, which is the student policy from the Meta-Imitation Learning perspective, is dependent on all previous observations and actions. Intuitively, the dependence on all previous observations and actions makes sense because any of the individual observations, or, more likely, the combination of observations over time, contains information about the dynamics parameters 𝚵 and about the ground-truth state s.

This is illustrated in Figure 3 and Figure 7C where we show how the relation of observations over time carries information about the dynamics parameters. By looking at the observation-action history, the policy can observe that, for example, the effect of the motor commands is always delayed by one timestep. Note that this is a simplification by using a pure delay/dead time, whereas in reality the temporal relationship between motor commands and motor speeds is more closely modeled as a first-order low-pass filter. Furthermore, it can be observed that a motor command of 1 corresponds to an observed acceleration of 1, but a motor command of 2 corresponds to an observed acceleration of 4. Hence it can infer the curvature of the thrust curve.

Therefore, from both the theory and intuition, we can conclude that the foundation policy should be able to take past observations and actions as the input and then output the predicted distribution over optimal actions as closely as possible. Therefore, we model the action distribution of the foundation policy (student in the Meta-Imitation Learning framework) with dependencies on all previous observations and actions in Figure 7A. Even given the whole history of observations and actions, there might still be mutual information left between s𝑡 and 𝚵. Hence, we cannot expect the distribution a𝑡𝜋 to model the optimal action distribution a𝑡∗ exactly.

Instead, we want to model it as closely as possible and hence phrase the problem as variational inference, where we try to minimize the Kullback-Leibler (KL) divergence between the predicted optimal action distribution and the actual optimal action distribution. Note that due to the nonlinearities in the system dynamics, the actual optimal action distribution is not tractable and that we approximate it by training expert teacher policies until convergence.

Please refer to the Supplementary Materials (45) for a full derivation of the Mean-Squared Error (MSE) training objective from Maximum Likelihood Estimation (MLE).

Whereas the Bayesian Network in Figure 7A is a formal/mathematical probabilistic model, Figure 1B shows our proposed practical method for modeling the various conditional probability distributions that constitute it:

- 1. Dynamics Distribution/Domain Randomization: This distribution implements the 𝚵 node.
- 2. RL Pre-Training: We use RL to train teacher policies that act as an oracle for the optimal

actiondistributionnodea𝑡∗.Sincewetrain1000specializedactors,thea𝑡∗ nodeisimplemented by a mixture policy, where the selected teacher is dependent on the dynamics parameters 𝚵,

which is also well characterized by the Bayesian Network through the dependence of a𝑡∗ on 𝚵.

- 3. Meta-Imitation Learning / Student Policy: This models the partially observable action

distribution node a𝑡𝜋 and is implemented by a recurrent policy, which takes a history of observations and actions as input.

- 4. Deployment: We deploy the foundation policy onto different, unseen, real-world quadrotors. We assume that the dynamics of most real quadrotors are in-distribution with respect to the distribution over dynamics parameters p(𝚵).

In the following, we describe these modules of the RAPTOR architecture in more detail.

##### Domain Randomization

We want the resulting foundation policy to be able to control a wide range of quadrotors. The RAPTOR philosophy is to employ radically wide domain randomization over 𝚵 and take advantage of emergent meta-learning (50) to produce a foundation policy that can adapt to unseen quadrotors zero-shot. To facilitate this, we need to design a distribution over realistic quadrotors that assigns a sufficient amount of probability mass to real-world quadrotors.

We are mainly concerned with the mass, geometric dimensions, inertia, thrust curves, torque coefficients, and motor delays, since these capture the most important parts of the quadrotor dynamics. These quantities are correlated in non-linear ways, making it intractable to directly formulate the joint distribution in analytical form.

Hence, we factorize the distribution based on physical properties. By formulating the distribution in this factorized way, we can use efficient ancestral sampling to sample new quadrotors. Please refer to the supplementary Figure S1 for a graphical model corresponding to this factorization and ancestral sampling scheme. Due to this scheme, we prevent having to resort to heavy sampling mechanisms like Markov Chain Monte Carlo (MCMC), and can sample the root (shaded) quantities from simple, independent uniform distributions. Even though the marginal distributions are independent, the computed nodes are dependent on multiple inputs and are correlated in a physically plausible way.

Please refer to the Supplementary Materials (45) for the detailed equations that establish the physically plausible correlations.

##### Training Methodology

After establishing a realistic distribution over quadrotors, the question arises on how to devise a foundation control policy that can adapt to any one of them. We initially experimented using end-to-end RL with a single recurrent policy and critic, in the spirit of meta-RL (51,52), but we did not see signs of convergence, and the training was very time-intensive due to the sequential nature of training Recurrent Neural Networks (RNNs).

Since we knew that by combining (7) and (39), we can train good individual RL policies for a wide range of quadrotors, and due to the dependencies derived from the probabilistic model, we made the design choice to factorize the architecture into a pre-training and post-training/MetaImitation Learning stage. This architectural division is also inspired by the common practice of splitting the training of language and vision foundation models into pre- and post-training (53).

###### Pre-Training

In the pre-training phase, we take 1000 quadrotors sampled from the distribution described in the Domain Randomization subsection and train a dedicated expert policy for each of them by creating an independent MDP for each set of sampled domain parameters 𝚵. We also make the ground-truth states directly observable because this expert policy does not need to be deployed on hardware. Since we are not constrained by the deployment onto hardware, we can overparameterize it to aid the training (36). We use fully-connected three-layer neural networks with a hidden dimensionality of 64, making each teacher policy > 3× larger than the condensed foundation policy in terms of parameters. The training pipeline is adapted from (7) with five modifications:

- 1. Switching from TD3 to SAC because we observed slightly more robust training dynamics in SAC. Note that we use an off-policy method because in our experience they are much more reliable than on-policy methods like PPO and, for example, do not require cherry-picking random seeds. The latter is of utmost importance because we do not have the capacity to supervise each of the 1000 training runs, and hence rely on each of them finding a good policy without any adjustments to hyperparameters.
- 2. Training for longer to ensure convergence for all quadrotors.
- 3. Adjusting the reward function, adding a penalty for termination and for the action derivative.
- 4. Removing the curriculum because we found that the changes to the reward function stabilize the training without the need for a curriculum.
- 5. Ground-truth motor RPM states. The teacher policies are never deployed in reality, so instead of feeding a proprioceptive action history to account for the unobservable motor states as in (7), the teachers can directly observe the ground-truth motor states. This also makes the actor-critic architecture symmetric.

We do these modifications to trade off wall-clock training time for highly reliable training dynamics, and we found them to yield high-quality teacher policies in all 1000 cases without cherry-picking random seeds and without requiring case-by-case modifications, even though the dynamics of the quadrotors vary drastically as described in the Domain Randomization subsection.

The teachers observe the states fully oteacher = {p, R(q), v, 𝝎, a𝑡−1, 𝝎𝑚, fext}. We train using a position control objective where the quadrotor is initialized in a random state (for example, up to 90◦ tilt) and the policy has to navigate it back to the origin with zero yaw while also minimizing linear/angular velocity and action changes. To prepare the policy for trajectory tracking, we also train with the objective of tracking a relatively slow trajectory sampled from a second-order Langevin process. The Supplementary Materials (45) contain additional details about the motivation for and the implementation of the distribution over reference trajectories.

###### Meta-Imitation Learning

After training 1000 teacher policies, we would like to distill all of their behaviors into a single student foundation policy. From the perspective of each teacher policy, there are no hidden/latent parameters because each teacher policy can assume that it always interacts with the same quadrotor

𝚵. However, in aggregate, and from the perspective of the student policy, the parameters of the quadrotor 𝚵 it is interacting with are not observable and need to be inferred as described in the Materials and Methods section. Due to the variable number of past steps (see Figure 7A), we design a Gated Recurrent Unit (GRU) (54)-based foundation policy architecture as displayed in Figure 7B.

The relatively small hidden dimensionality of 16 is justified by the scaling experiments in the Meta-Imitation Learning subsection of the Results section. Due to the recurrence, the policy can theoretically ”access” all the previous observations and actions.

We refer to our proposed algorithm as Meta-Imitation Learning because the student not only needs to learn to recreate the teachers’ outputs from a different set of inputs/sensors, but also must learn to perform inference about the current MDP that it is acting in. Each quadrotor constitutes a separate MDP because the transition function varies based on the random dynamics parameters 𝚵. We currently only tackle the case where the dynamics parameters change, but in the future, we will also incorporate, for example, changes in the reward function.

Our proposed method is conceptually similar to the DAgger algorithm (55) but differs in two key ways, firstly in the aforementioned requirement for meta-learning and secondly in that we perform on-policy data collection (after warm-up) and learning whereas DAgger is performing on-policy data collection but also uses off-policy data (the aggregated dataset) for learning. Figure 8 shows our full proposed algorithm consisting of the sampling of 1000 random quadrotors and the two main learning phases: pre- and post-training.

In the post-training phase, we distill the combined behaviors of the 1000 teachers into the student foundation policy. We train it for 1000 epochs and solely use on-policy data after a warmup (using teacher rollouts) of 10 epochs. The task of the student foundation policy, characterized by its parameters 𝜽, is to predict the teachers’ motor commands as closely as possible just based on the history of observations and (its own actions), without knowing the teacher or dynamics parameters

- at hand. As shown in Figure 7A, this forces the policy to infer the parameters of 𝚵 that are relevant for the

input/output behavior of the system. This meta-learning using in-context reasoning is the central part of our proposed method. Additionally, we propose the use of on-policy imitation learning, where we neither use the actions of the teachers during rollout (in contrast to the 𝛽 trade-off in (55)) nor use trajectories from past policies. We use on-policy imitation learning because full dataset aggregation as in DAgger (55) is infeasible due to memory constraints, and we also find it to learn faster and better policies.

##### Computational Aspects

Computationally, the separation into pre-training and post-training/meta-imitation learning is a major advantage of the RAPTOR framework. This decouples the time/compute-intensive pretraining and renders it ”embarrassingly parallel” (56). This can be seen from Figure 1B, where the teacher training processes are independent. Hence, we can horizontally scale out the number of training processes over multiple processors and/or machines, linearly speeding the pre-training up to the ceiling, which is the 31 min duration of each training run (at 1000 cores in parallel). In contrast to LLM pre-training, where the gradients have to be communicated between all nodes at every training step, in RAPTOR, pre-training is entirely independent and communication/synchronization is only required after pre-training, in the distillation/meta-imitation learning phase, which is about three orders of magnitude less computationally intensive than the pre-training.

- 1 P ← [ ] ; // List of dynamics parameters // Init foundation policy weights
- 2 θ ← init weights() ;

- 3 Π∗ ← [ ] ; // List of teacher checkpoints
- 4 for i ← 1 to 1000 do

- 5 Ξ ← sample dynamics parameters();

- 6 P.append(Ξ);
- 7 end
- 8 for i ← 1 to 1000 do

- 9 Ξ ← P[i]; // Train for 1e6 environment steps // Returns the best checkpoint
- 10 θ∗ ← run SAC(Ξ);

- 11 Π∗.append(θ∗);
- 12 end
- 13 for epoch ← 1 to 1000 do

- 14 T ← [ ] ; // List of trajectories
- 15 for i ← 1 to 1000 do

- 16 Ξ ← P[i];
- 17 θ∗ ← Π∗[i] ; // Teacher weights
- 18 for j ← 1 to 10 do

- 19 if epoch ≤ 10 then // Warmup using teacher

- 20 τ ← sample trajectory(Ξ,θ∗);

- 21 else // On-policy sampling

- 22 τ ← sample trajectory(Ξ,θ);

- 23 end
- 24 τ∗a ← forward(θ∗,τ);
- 25 T.append((τ,τ∗a));
- 26 end
- 27 end
- 28 B ← shuffle into batches(T);

- 29 foreach (X,Y) ∈ B do

- 30 Ypred ← forward(θ,X);
- 31 L ← MSE(Ypred,Y);
- 32 L.backward();
- 33 θ ← adam step(θ);

- 34 end
- 35 end

###### Figure 8: Meta-Imitation Learning Algorithm.

#### References and Notes

- 1. G. Li, X. Liu, G. Loianno, Human-Aware Physical Human–Robot Collaborative Transportation and Manipulation With Multiple Aerial Robots. IEEE Transactions on Robotics 41, 762–781

(2025), doi:10.1109/TRO.2024.3502508.

- 2. A. Ollero, et al., The AEROARMS Project: Aerial Robots with Advanced Manipulation Capabilities for Inspection and Maintenance. IEEE Robotics and Automation Magazine 25 (4), 12–23 (2018), doi:10.1109/MRA.2018.2852789.
- 3. M. Tranzatto, et al., CERBERUS in the DARPA Subterranean Challenge. Science Robotics 7 (66), eabp9742 (2022), doi:10.1126/scirobotics.abp9742, https://www.science.org/ doi/abs/10.1126/scirobotics.abp9742.
- 4. Y. Song, A. Romero, M. M¨uller, V. Koltun, D. Scaramuzza, Reaching the limit in autonomous racing: Optimal control versus reinforcement learning. Science Robotics 8 (82), eadg1462 (2023), doi:10.1126/scirobotics.adg1462, https://www.science.org/ doi/abs/10.1126/scirobotics.adg1462.
- 5. E. Kaufmann, et al., Champion-level drone racing using deep reinforcement learning. Nature 620 (7976), 982–987 (2023), doi:10.1038/s41586-023-06419-4.
- 6. R. Ferede, T. Blaha, E. Lucassen, C. De Wagter, G. C. de Croon, One Net to Rule Them All: Domain Randomization in Quadcopter Racing Across Different Platforms. arXiv preprint arXiv:2504.21586 (2025).
- 7. J. Eschmann, D. Albani, G. Loianno, Learning to Fly in Seconds. IEEE Robotics and Automation Letters 9 (7), 6336–6343 (2024), doi:10.1109/LRA.2024.3396025.
- 8. X.B.Peng,M.Andrychowicz,W.Zaremba,P.Abbeel,Sim-to-RealTransferofRoboticControl with Dynamics Randomization, in IEEE International Conference on Robotics and Automation (ICRA) (2018), pp. 3803–3810, doi:10.1109/ICRA.2018.8460528.
- 9. A. Loquercio, et al., Deep drone racing: From simulation to reality with domain randomization. IEEE Transactions on Robotics 36 (1), 1–14 (2019).
- 10. D. Hanover, et al., Autonomous drone racing: A survey. IEEE Transactions on Robotics 40, 3044–3067 (2024).
- 11. A. Radford, et al., Learning Transferable Visual Models From Natural Language Supervision, in Proceedings of the 38th International Conference on Machine Learning, M. Meila, T. Zhang, Eds. (PMLR), vol. 139 of Proceedings of Machine Learning Research (2021), pp. 8748–8763, https://proceedings.mlr.press/v139/radford21a.html.
- 12. T. Brown, et al., Language models are few-shot learners. Advances in neural information processing systems 33, 1877–1901 (2020).
- 13. J. Kaplan, et al., Scaling laws for neural language models. arXiv preprint arXiv:2001.08361

(2020).

- 14. E. Kaufmann, L. Bauersfeld, D. Scaramuzza, A Benchmark Comparison of Learned Control Policies for Agile Quadrotor Flight, in International Conference on Robotics and Automation (ICRA) (2022), pp. 10504–10510, doi:10.1109/ICRA46639.2022.9811564.
- 15. R. Zhang, D. Zhang, M. W. Mueller, Proxfly: Robust control for close proximity quadcopter flight via residual reinforcement learning. arXiv preprint arXiv:2409.13193 (2024).
- 16. J. Heeg, Y. Song, D. Scaramuzza, Learning quadrotor control from visual features using differentiable simulation. arXiv preprint arXiv:2410.15979 (2024).
- 17. J. Xing, I. Geles, Y. Song, E. Aljalbout, D. Scaramuzza, Multi-task reinforcement learning for quadrotors. IEEE Robotics and Automation Letters (2024).
- 18. S. Gronauer, M. Kissel, L. Sacchetto, M. Korte, K. Diepold, Using simulation optimization to improve zero-shot policy transfer of quadrotors, in 2022 IEEE/RSJ International Conference on Intelligent Robots and Systems (IROS) (IEEE) (2022), pp. 10170–10176.
- 19. R. Ferede, G. de Croon, C. De Wagter, D. Izzo, End-to-end neural network based optimal quadcopter control. Robotics and Autonomous Systems 172, 104588 (2024).
- 20. R. Ferede, C. De Wagter, D. Izzo, G. C. De Croon, End-to-end reinforcement learning for timeoptimal quadcopter flight, in 2024 IEEE International Conference on Robotics and Automation (ICRA) (IEEE) (2024), pp. 6172–6177.
- 21. L. Balandi, P. Robuffo Giordano, M. Tognon, Acceleration-Based Inner-Loop Control and MPC for Aerial Robots: Advantages and Drawbacks, in European Robotics Forum (Springer)

(2025), pp. 75–80.

- 22. S. M. Hegre, W. Rehberg, M. Kulkarni, K. Alexis, A Neural Network Mode for PX4 on Embedded Flight Controllers. arXiv preprint arXiv:2505.00432 (2025).
- 23. D. Zhang, et al., A Learning-Based Quadcopter Controller With Extreme Adaptation. IEEE Transactions on Robotics 41, 3948–3964 (2025), doi:10.1109/TRO.2025.3577037.
- 24. D. Chen, B. Zhou, V. Koltun, P. Kr¨ahenbu¨hl, Learning by cheating, in Conference on robot learning (PMLR) (2020), pp. 66–75.
- 25. J. Lee, J. Hwangbo, L. Wellhausen, V. Koltun, M. Hutter, Learning quadrupedal locomotion over challenging terrain. Science Robotics 5 (47), eabc5986 (2020), doi:10.1126/scirobotics. abc5986, https://www.science.org/doi/abs/10.1126/scirobotics.abc5986.
- 26. A. Kumar, Z. Fu, D. Pathak, J. Malik, RMA: Rapid Motor Adaptation for Legged Robots, in Proceedings of Robotics: Science and Systems (Virtual) (2021), doi:10.15607/RSS.2021.XVII. 011.
- 27. M. Paluch, F. Bolli, P. Moure, X. Deng, T. Delbruck, A-NC: Adaptive Neural Control with implicit online inference of privileged parameters, in Proceedings of the 7th Annual Learning for Dynamics &amp; Control Conference, N. Ozay, L. Balzano, D. Panagou, A. Abate, Eds. (PMLR), vol. 283 of Proceedings of Machine Learning Research (2025), pp. 987–998, https: //proceedings.mlr.press/v283/paluch25a.html.

- 28. T. Yu, et al., Meta-World: A Benchmark and Evaluation for Multi-Task and Meta Reinforcement Learning, in Proceedings of the Conference on Robot Learning, L. P. Kaelbling, D. Kragic, K. Sugiura, Eds. (PMLR), vol. 100 of Proceedings of Machine Learning Research (2020), pp. 1094–1100, https://proceedings.mlr.press/v100/yu20a.html.
- 29. T. Yu, et al., Gradient Surgery for Multi-Task Learning, in Advances in Neural Information Processing Systems, H. Larochelle, M. Ranzato, R. Hadsell, M. Balcan, H. Lin, Eds. (Curran Associates, Inc.), vol. 33 (2020), pp. 5824–5836, https://proceedings.neurips.cc/ paper_files/paper/2020/file/3fe78a8acf5fda99de95303940a2420c-Paper.pdf.
- 30. P. Henderson, et al., Deep reinforcement learning that matters, in Proceedings of the AAAI conference on artificial intelligence, vol. 32 (2018).
- 31. Y. Wu, E. Mansimov, R. B. Grosse, S. Liao, J. Ba, Scalable trust-region method for deep reinforcement learning using kronecker-factored approximation. Advances in neural information processing systems 30 (2017).
- 32. H. P. Van Hasselt, A. Guez, M. Hessel, V. Mnih, D. Silver, Learning values across many orders of magnitude. Advances in neural information processing systems 29 (2016).
- 33. W. C. Lewis II, M. Moll, L. E. Kavraki, How much do unstated problem constraints limit deep robotic reinforcement learning? arXiv preprint arXiv:1909.09282 (2019).
- 34. K. Clary, E. Tosch, J. Foley, D. Jensen, Let’s play again: Variability of deep reinforcement learning agents in atari environments. arXiv preprint arXiv:1904.06312 (2019).
- 35. R. Agarwal, M. Schwarzer, P. S. Castro, A. C. Courville, M. Bellemare, Deep reinforcement learning at the edge of the statistical precipice. Advances in neural information processing systems 34, 29304–29320 (2021).
- 36. M. Belkin, D. Hsu, S. Ma, S. Mandal, Reconciling modern machine-learning practice and the classical bias–variance trade-off. Proceedings of the National Academy of Sciences 116 (32), 15849–15854 (2019).
- 37. A. Molchanov, et al., Sim-to-(Multi)-Real: Transfer of Low-Level Robust Control Policies to Multiple Quadrotors, in IEEE/RSJ International Conference on Intelligent Robots and Systems (IROS) (2019), pp. 59–66, doi:10.1109/IROS40897.2019.8967695.
- 38. T.Baca,etal.,TheMRSUAVsystem:Pushingthefrontiersofreproducibleresearch,real-world deployment, and education with autonomous unmanned aerial vehicles. Journal of Intelligent & Robotic Systems 102 (1), 26 (2021).
- 39. J. Eschmann, D. Albani, G. Loianno, Data-Driven System Identification of Quadrotors Subject to Motor Delays, in IEEE/RSJ International Conference on Intelligent Robots and Systems (IROS) (2024), pp. 8095–8102, doi:10.1109/IROS58592.2024.10801441.
- 40. G. Alain, Y. Bengio, Understanding intermediate layers using linear classifier probes. arXiv preprint arXiv:1610.01644 (2016).

- 41. A. Dosovitskiy, et al., An image is worth 16x16 words: Transformers for image recognition at scale. arXiv preprint arXiv:2010.11929 (2020).
- 42. M. Oquab, et al., Dinov2: Learning robust visual features without supervision. arXiv preprint arXiv:2304.07193 (2023).
- 43. R.Mahony,T.Hamel,J.-M.Pflimlin,Nonlinearcomplementaryfiltersonthespecialorthogonal group. IEEE Transactions on automatic control 53 (5), 1203–1218 (2008).
- 44. S. O. Madgwick, et al., An efficient orientation filter for inertial and inertial/magnetic sensor arrays (2010).
- 45. Materials and methods are available as supplementary material.
- 46. P. Kunapuli, J. Welde, D. Jayaraman, V. Kumar, Leveling the Playing Field: Carefully Comparing Classical and Learned Controllers for Quadrotor Trajectory Tracking, in Proceedings of Robotics: Science and Systems (Los Angeles, United States of America) (2025).
- 47. S. Ross, B. Chaib-draa, J. Pineau, Bayes-adaptive pomdps. Advances in neural information processing systems 20 (2007).
- 48. D. Koller, N. Friedman, Probabilistic graphical models: principles and techniques (MIT press)

(2009).

- 49. J. Pearl, Probabilistic Reasoning in Intelligent Systems: Networks of Plausible Inference (Morgan Kaufmann Publishers Inc., San Francisco, CA, USA) (1988).
- 50. OpenAI, et al., Solving Rubik’s Cube with a Robot Hand (2019).
- 51. J. X. Wang, et al., Learning to reinforcement learn. arXiv preprint arXiv:1611.05763 (2016).
- 52. Y. Duan, et al., RL2: Fast reinforcement learning via slow reinforcement learning. arXiv preprint arXiv:1611.02779 (2016).
- 53. J. Achiam, et al., Gpt-4 technical report. arXiv preprint arXiv:2303.08774 (2023).
- 54. K. Cho, et al., Learning phrase representations using RNN encoder-decoder for statistical machine translation. arXiv preprint arXiv:1406.1078 (2014).
- 55. S. Ross, G. Gordon, D. Bagnell, A reduction of imitation learning and structured prediction to no-regret online learning, in Proceedings of the fourteenth international conference on artificial intelligence and statistics (JMLR Workshop and Conference Proceedings) (2011), pp. 627–635.
- 56. C. Moler, Matrix computation on distributed memory multiprocessors. Hypercube Multiprocessors 86 (181-195), 31 (1986).
- 57. J. Eschmann, D. ALBANI, G. Loianno, RAPTOR: A Foundation Policy for Quadrotor Control

###### (2025), doi:10.5281/zenodo.17096679, https://doi.org/10.5281/zenodo.17096679.

- 58. Supplementary Code and Data Repository, Github: rl-tools/raptor, https://github.com/ rl-tools/raptor.
- 59. Project Page, Static Website, https://raptor.rl.tools/.
- 60. Supplementary Video, YouTube, https://youtu.be/hVzdWRFTX3k.
- 61. S. Sarkka, A. Solin, J.Hartikainen, Spatiotemporal Learning viaInfinite-Dimensional Bayesian Filtering and Smoothing: A Look at Gaussian Process Regression Through Kalman Filtering. IEEE Signal Processing Magazine 30 (4), 51–61 (2013), doi:10.1109/MSP.2013.2246292.
- 62. S. S¨arkk¨a, A. Solin, Applied stochastic differential equations, vol. 10 (Cambridge University Press) (2019).
- 63. C. Berner, et al., Dota 2 with large scale deep reinforcement learning. arXiv preprint arXiv:1912.06680 (2019).

#### Acknowledgments

We thank Professor Van Anh Ho and Quang Ngoc Pham for letting us test the foundation policy on the soft quadrotor.

Funding: This work was supported in part by the National Science Foundation (NSF) CAREER program under Grant 2145277, and in part by the Defense Advanced Research Projects Agency (DARPA) Young Faculty Award under Grant D22AP00156-00.

Author Contributions: J.E. formulated the main ideas, implemented them, conducted the experiments and wrote the paper. D.A. and G.L. provided supervision and guided the direction during all phases of the project and helped write the paper.

Competing Interests: The authors declare that they have no competing interests.

Data and Materials Availability: The code and dataset of sampled quadrotor dynamics as well as the trained teacher checkpoints are available from https://doi.org/10.5281/zenodo. 17096679 (57) and the Git repository https://github.com/rl-tools/raptor (58). Please also refer to the project page at https://raptor.rl.tools (59) where an interactive simulation can be used to test the RAPTOR policy. The full-length, high-quality video can also be accessed at https://youtu.be/hVzdWRFTX3k (60).

##### Supplementary Materials

Figure S1 Movie S1 to S8 Data S1

#### Supplementary Materials for RAPTOR: A Foundation Policy for Quadrotor Control

Jonas Eschmann∗, Dario Albani, Giuseppe Loianno

∗Corresponding author. Email: jonas.eschmann@berkeley.edu

###### This PDF file includes:

Materials and Methods Figure S1 Captions for Movies S1 to S8 Captions for Data S1

###### Other Supplementary Materials for this manuscript:

Movies S1 to S8 Data S1

##### Materials and Methods

Quadrotor Dynamics The L2F simulator (7) uses the following equations of motion:

- p = v
- q = q ◦ [0 𝝎/2]⊤

∑︁ 3

1 𝑚

v =

r𝑓𝑖 𝑓𝑖 + fext + g

R(q)

𝑖=0

∑︁2

𝑐𝑓𝑗 𝜔𝑚𝑖 𝑗 𝝎 = J−1 (𝝉 + (J𝝎) × 𝝎) 𝝉 =

𝑓𝑖 =

𝑗=0

∑︁3

r𝑝𝑖 × r𝑓𝑖 𝑓𝑖 + r𝜏𝑖𝑐𝑚 𝑓𝑖

𝑖=0

⊤

𝑙arm √2

𝑙arm √2

r𝑝𝑖 = ±

, 0

, ±

r𝜏𝑖 = [0, 0, ±1]⊤

𝑇𝑚−↑1 𝝎𝑠𝑝𝑖 − 𝝎𝑚𝑖 , 𝝎𝑚𝑖 ≤ 𝝎𝑠𝑝𝑖 𝑇𝑚−↓1 𝝎𝑠𝑝𝑖 − 𝝎𝑚𝑖 , 𝝎𝑚𝑖 > 𝝎𝑠𝑝𝑖

𝝎𝑚𝑖 =

𝝎𝑠𝑝 := a

Where 𝝎 is in the body frame. We only consider the case of planar quadrotors, where r𝑓𝑖 = [0, 0, 1]⊤ ∀𝑖 ∈ 0 . . . 3. r𝑝𝑖 and r𝜏𝑖 are set up according to the Crazyflie motor layout conventions: (front-right, back-right, back-left, front-left) and (CCW, CW, CCW, CW), respectively. Note that this corresponds to the top-down view and the body frame is following the Front-Left-Up (FLU) conventions. CW corresponds to a torque direction of r𝜏𝑖 = [0, 0, 1]. When deploying on platforms with other motor-layout conventions, a re-mapping of the motor commands is applied.

###### Linear Velocity Feedback Delay Mitigation

We counteract the linear velocity delay experienced by the non-EKF-based platforms by overlaying a simple accelerometer integral that is grounded through an exponential decay. This can also be interpreted as a convolution of the accelerometer data with an Infinite Impulse Response (IIR) filter. Before the convolution, the gravity is subtracted by applying the current orientation estimate to the accelerometer data.

a𝑔(𝑡) = R𝑇(𝑡)a(𝑡) − g (S1) v𝑎(𝑡) = ∫ 𝑡

a𝑔(𝜏)𝑒−𝑡−𝑇𝜏 𝑑𝜏 (S2)

0

We use the following discrete approximation to implement the filter:

𝛼 = 𝑒−Δ𝑇𝑡 (S3) v𝑡𝑎 = 𝛼v𝑡−1

𝑎 + a𝑡𝑔Δ𝑡 (S4)

We find that this mitigation substantially reduces the z-axis oscillations on the non-EKF-based platforms.

###### Sampling Quadrotors

We establish a physically plausible generative distribution over quadrotors through the following relations:

𝑟t2w ∼ Uniform(1.5, 5) (S5) 𝑚min = 0.02, 𝑚max = 5 (S6)

√𝑚min, √3𝑚max) (S7) 𝑓 (𝜔𝑚𝑖) = 𝑐𝑓0 + 𝑐𝑓1𝜔𝑚𝑖 + 𝑐𝑓2𝜔2𝑚𝑖 (S8)

𝑚 = 𝑠3, 𝑠 ∼ Uniform( 3

𝜔𝑚𝑖 ∈ [0, 1], ∑︁

𝐶𝑓𝑖 = 1, 𝐶𝑓0 = 0.032, 𝐶𝑓1 = 0.131, 𝐶𝑓2 = 0.837 (S9) 𝑇 = 𝑟t2w · 9.81 · 𝑚 (S10)

𝑖

𝑇 4

- (S11)
- (S12)

𝑐𝑓𝑖 = 𝐶𝑓𝑖

The idea is to first sample the thrust-to-weight ratio 𝑟t2w and mass 𝑚 to create the thrust curve. The thrust curve consists of the coefficients 𝐶𝑓0,𝐶𝑓1,𝐶𝑓2 for the constant, linear and quadratic term respectively. To relate the thrust-to-weight ratio to the thrust curve we require the mass. To sample the mass we need to consider that it grows cubically with the size (arm length, assuming constant density). If we were to uniformly sample the mass, we would disproportionately bias the distribution towards large quadrotors. Instead, we pose that quadrotors are rather uniformly distributed in size so we uniformly sample a scale 𝑠 that we map back cubically into the desired mass range 𝑚 ∈ [𝑚min, 𝑚max] to get a realistic distribution over masses. Note that w.l.o.g., we normalize the motor effort setpoints 𝜔𝑚𝑖 and the baseline thrust curve coefficients 𝐶𝑓𝑖. This allows us to simply scale the baseline thrust curve shape (taken from the Crazyflie (39)) to reflect the sampled thrust-to-weight ratio. Note: The baseline thrust curve coefficients 𝐶𝑓𝑖 are capitalized while the coefficients 𝑐𝑓𝑖 of the sampled thrust curve 𝑓 are lower-case.

√3𝑚 𝑙arm is not always constant so we

Due to different design considerations, the mass-size ratio

establish the mass-size ratio of the Crazyflie 𝑅𝑚𝑠 as the base value and sample variations around that.

√𝑚crazyflie 𝑙arm,crazyflie ≈ 7.90 (S13)

3

𝑅𝑚𝑠 =

𝑢 ∼ N(−0.1, 0.1) (S14)

1

1−𝑢 if 𝑢 < 0 1 + 𝑢 if 𝑢 ≥ 0

(S15)

𝑠𝑚𝑠 =

√3𝑚 𝑙arm

=! 𝑠𝑚𝑠𝑅𝑚𝑠 (S16)

𝑟𝑚𝑠 =

√3𝑚 𝑠𝑚𝑠𝑅𝑚𝑠

- (S17)
- (S18)

𝑙arm =

We intended to use a reciprocal deviation 𝑠ms of ±10% but accidentally used a normal instead of a uniform distribution. In a post-hoc analysis we find that the resulting distribution has a mean and standard deviation of ≈ 7.24 ± 0.66. This incidentally fits the empirical distribution of mass-size deviations of the quadrotors in Figure 4 with a mean and standard deviation of ≈ 7.66±1.93 better than the intended distribution of just 10% uniform reciprocal deviations. For future works we advise to investigate directly sampling from a normal distribution with a wider standard deviation that is closer to the empirical standard deviation of the actual quadrotors.

The sampled mass-size ratio allows us to compute the arm length 𝑙arm which, in combination with the assumption that the quadrotor is in a symmetric X configuration, defines the geometry.

Finally, we need to sample the inertia based on the previously sampled quantities: 𝑟t2i ∼ Uniform(40, 1200) (S19) 𝜏 = 𝑇 ·

√2 · 𝑙arm (S20) 𝐽𝑥𝑥 = 𝐽𝑦𝑦 =

𝜏 𝑟t2i

(S21)

𝐽𝑥𝑥 + 𝐽𝑦𝑦

2 · 1.832 (S22) (S23)

𝐽𝑧𝑧 =

For sampling the inertia, we introduce another ratio, the torque-to-inertia ratio 𝑟t2i. We collect quadrotor dynamics parameters from the literature and find a realistic randomization range to be between 40 and 1200. After sampling the torque-to-inertia ratio, we can use the previously sampled thrust-to-weight, mass and size (arm length) parameters to calculate the x and y inertia. To get the z inertia, we apply the rule of (39).

Furthermore, we can independently sample the moment constant as well as the motor delays because they do not correlate strongly with any of the other variables in our experience:

𝑐𝑚 ∼ Uniform(0.005, 0.05) (S24) 𝑇𝑚↑ ∼ Uniform(0.03, 0.1) (S25) 𝑇𝑚↓ ∼ Uniform(0.03, 0.3) (S26)

Finally, we sample the standard deviation used for sampling the random disturbance force fext

- as 10% of the surplus thrust 𝑟t2w − 1:

𝜎fext ∼ Uniform(0, (𝑟t2w − 1) · 0.1) (S27)

The idea behind choosing 10% is that by applying the 3𝜎-rule, the sampled random disturbance will be confined at 30% of the surplus thrust with a ∼ 99.7% probability. This makes it exceedingly unlikely that we sample forces that are too strong to be compensated by the control policy.

###### Sampling Trajectories

During pre-training, the policies are Markovian and only consider the current observation (plus previous actions). This means that (in the absence of aerial drag-forces from linear velocity) trajectory tracking and position control appear identical to the policy because we can just feed the position and linear velocity error w.r.t. the trajectory as observations and achieve good trajectory tracking (7). In the case of a stateful, non-Markovian policy as with the recurrent foundation policy, this is not the case anymore. If we add the dynamics of the trajectory itself to the dynamics of the quadrotor through the error-state observation, the trajectory of error-state observations does not appear like a quadrotor anymore.

A simple example would be a reference trajectory with a jump in linear velocity. From the perspective of a stateful policy that has only been trained on position control (no trajectory dynamics in the observation space) this abrupt change in linear velocity appears like a quadrotor with an unrealistically high thrust-to-weight ratio, unrealistically fast angular response and/or even a world with much larger than 1 G gravity. The latter happens if, for example, the velocity step is downwards in z and the quadrotor is not upside down or if the action inputs have been low/zero.

To counter-act this, we train the expert and student policies using a simple probabilistic mixture model of trajectories. With 50% probability, the task is just tracking the null-trajectory (position control, going back to the origin from any initial state). In the other 50% the task is to track randomly sampled trajectories. Note that position and linear velocity are just offset by the trajectory (p := p − ptarget, v := v − vtarget) in the observations as well as in the reward function. We neither change the structure nor adjust the parameters.

We would like to cover a wide variety of possible reference trajectories. Trajectories are vectorvalued functions of time, so we need to design a broad distribution over functions. Here we take inspiration from the Gaussian Process (GP) community, which has been concerned with designing prior distributions over functions since its inception. Additionally, we require the sampling of reference trajectories to not slow down the simulation too much. Hence, we choose to sample the reference trajectories from a second-order Langevin process. A second-order Langevin process corresponds to a GP with a certain structure in the kernel (depending on the parameters of the Langevin process) (61,62) but we can easily sample it incrementally while simulating the quadrotor dynamics.

Based on the results described in the Trajectory Tracking subsection, we find that this approach works well for moderately agile trajectory tracking and even generalizes from second-order Langevin random walks to cyclical Lissajous trajectories. But we acknowledge that, although the second-order Langevin process covers the space of smooth functions relatively well, many trajec-

tories with real-world use-cases such as step-functions/responses are not covered or exponentially unlikely (such as cyclical trajectories).

###### Meta-Imitation Learning Objective

We do not perform variational inference on a case-by-case basis but instead in an amortized fashion, where the inference itself is conducted by the recurrent neural network policy at test time. This amortization makes the inference very compute efficient and allows us to deploy the foundation policy onto even the tiniest microcontrollers while meeting real-time constraints at high frequencies.

For tractability of the KL divergence we assume the action distributions are parameterized Gaussians:

𝑝(a∗

𝑡 | s𝑡, 𝚵) ≈ N(a∗

𝑡 ; 𝝅∗(s𝑡, 𝚵), I) (S28)

𝝅∗(s𝑡, 𝚵) := 𝝅∗𝚵(s𝑡) (S29) 𝑝(a𝑡𝜋 | o0, . . . , o𝑡, a0, . . . , a𝑡−1) ≈ N(a𝑡𝜋; 𝝅(o0, . . . , (S30)

o𝑡, a0, . . . , a𝑡−1), I) (S31) = N(a𝑡𝜋; 𝝅(o0:𝑡, a0:𝑡−1), I) (S32)

Where 𝝅∗𝚵 is one of the 1000 teacher policies trained for the particular quadrotor/set of dynamics parameters 𝚵 and 𝝅 is the student foundation policy.

We can see that the input shape of the foundation policy 𝝅 is dependent on the number of previous steps in the episode. Due to the sequential nature of the inputs, we choose a recurrent neural network architecture for three main reasons:

- 1. Computational Efficiency: We require computational efficiency for direct deployment on compute-constrained microcontrollers. Recurrent Neural Networks (RNNs) are O(1) in the history length 𝑁, each incremental step only requires a fixed amount of compute at inference time. In contrast, Convolutional Neural Networks (CNN) and attention are O(log(𝑁)) and O(𝑁) for each step, respectively.
- 2. Context Window Extrapolation: At inference time we would like the policy to fly for longer time than the context window used during training. During training the context is usually limited to not slow down the process too much. CNNs, by design, have a limited context window that cannot be extended. Similarly, attention, being a set-to-set mapping, requires position embeddings which complicate context window extrapolation.
- 3. Successful Use in Related Works: E.g. (50) and (63) have used recurrent policies successfully.

We find that a surprisingly small (in terms of number of parameters and compute requirements) three-layer recurrent neural network is sufficient to express the desired behavior described in the Introduction section. Figure 7B shows the architecture which contains a dense input layer, Gated Recurrent Unit (GRU) layer and a dense output layer. The initialization of the recurrent state (value

- at step 0) is all zeros and we feed back the previous output of the policy as an input. Due to the

small hidden dimensions the foundation policy only has 2084 parameters:

𝑃 = 𝑃input + 𝑃GRU + 𝑃output (S33) 𝑃input = 22 · 16 + 16 = 368 (S34) 𝑃GRU = 16 · 16 · 3 · 2 + 16 · 3 · 2 + 16 = 1648 (S35)

𝑃output = 16 · 4 + 4 = 68 (S36) 𝑃 = 2084 (S37)

We train the foundation policy using Meta-Imitation Learning where it acts as the student. During Meta-Imitation Learning, we want to adjust the student’s weights to minimize the KL divergence (also known as relative entropy) between the predicted optimal action distribution by the student and the optimal action distribution (approximated by the particular teacher for the current system dynamics):

𝑝(a𝑡∗ | s𝑡, 𝚵) 𝑝(a𝑡𝜋 = a𝑡∗ | o0:𝑡, a0:𝑡−1)

𝐷KL a∗

𝑡 ∥ a𝑡𝜋 = E

log

(S38) [. . .] = log 𝑝(a∗

a∗𝑡∼𝑝(a∗𝑡 |s𝑡,𝚵)

𝑡 | s𝑡, 𝚵) (S39) − log 𝑝(a𝑡𝜋 = a∗

𝑡 | o0:𝑡, a0:𝑡−1) (S40) (S41)

Hence, we want to find the log probabilities of the action distributions that we approximated as Gaussians before:

N(x; 𝝁, 𝚺) = (2𝜋)−𝑘/2 det(𝚺)−1/2 (S42) · exp − N(x; 𝝁, I) = 𝐶 · exp −

- 1

- 2(x − 𝝁)T𝚺−1(x − 𝝁) (S43)

- 1

- 2(x − 𝝁)T(x − 𝝁) (S44)

- 1

- 2∥x − 𝝁∥22 (S45)

= 𝐶 · exp −

Since we are aiming at quadrotors, both, the numerator and denominator multivariate Gaussian are 4-dimensional and the constants cancel.

𝑡 | s𝑡, 𝚵) (S46) − log 𝑝(a𝑡𝜋 = a∗

[. . .] = log 𝑝(a∗

𝑡 | o0:𝑡, a0:𝑡−1) (S47) 𝝁𝑇 :=𝝅∗(s𝑡, 𝚵) (S48) 𝝁𝑆 :=𝝅(o0:𝑡, a0:𝑡−1) (S49)

- 1

- 2∥a∗

𝑡 − 𝝁𝑇∥22 (S50) − log𝐶 +

[. . .] = log𝐶 −

- 1

- 2∥a∗

𝑡 − 𝝁𝑆∥22 (S51) (S52)

Thrust-toweight Scale

Mass-Size Deviation

Mass

Thrust curve

Size

Inertia

Torque-toinertia

Torque Coefficient

Motor Delays

###### Figure S1: Probabilistic Graphical Model for Ancestral Sampling of Quadrotors

We can split the second squared norm:

𝑡 − 𝝁𝑆∥22

∥a∗

𝑡 − 𝝁𝑇) + 𝝁𝑇 − 𝝁𝑆 ∥22

= ∥(a∗

𝑡 − 𝝁𝑇)T(𝝁𝑇 − 𝝁𝑆) + ∥(𝝁𝑇 − 𝝁𝑆)∥22

𝑡 − 𝝁𝑇)∥22 + 2(a∗

= ∥(a∗

Plugging back into Eq. S45:

1 2∥(𝝁𝑇 − 𝝁𝑆)∥22

𝑡 − 𝝁𝑇)T(𝝁𝑇 − 𝝁𝑆) +

[. . .] = (a∗

We remember that we take the expectation over [. . .] in Eq. S38 and that we assume that the teacher is an unbiased estimator for the optimal action (E a𝑡∗ − 𝝁𝑇 = 0):

- 1

- 2∥(𝝁𝑇 − 𝝁𝑆)∥22 (S53)

𝐷KL a∗

𝑡 ∥ a𝑡𝜋 = =

- 1

- 2∥(𝝅∗(s𝑡, 𝚵) − 𝝅(o0:𝑡, a0:𝑡−1))∥22 (S54)

Hence, under the mild assumption of unit standard deviations, we can conduct the MetaImitation Learning in a principled manner by minimizing the relative differential entropy between the (approximated) optimal action distribution and the predicted optimal action distribution by the student. In practice, we implement this by using Eq. S54, which is identical to the Mean-Squared Error (MSE), as the loss function and by optimizing the student policy’s parameters 𝜽 using gradient descent.

- Caption for Movie S1. Motivation and Introduction
- Caption for Movie S2. Trajectory Tracking Experiments
- Caption for Movie S3. Outdoor Experiments
- Caption for Movie S4. Disturbance Experiments: Poking
- Caption for Movie S5. Disturbance Experiments: Wind
- Caption for Movie S6. Disturbance Experiments: Different Propellers
- Caption for Movie S7. Agile Recovery / Rapid In-Context Learning Experiments
- Caption for Movie S8. Yaw Response Experiments

Caption for Data S1. Data and Code This package (57) contains all training and inference code as well as the complete pre-training data (including dynamics parameters and checkpoints of the 1000 quadrotors) and the resulting foundation policy. Please refer to the readme.txt for instructions.

