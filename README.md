# Dogfight-AI-Trainer-Reinforcement-Learning-for-Aerial-Combat-Simulation

An open-source framework for training AI agents in realistic dogfight scenarios using reinforcement learning, JSBSim flight dynamics, and Azure Machine Learning integration.

### Overview
Most defense AI today is incremental: faster data pipelines, slightly better classifiers, more automation of routine tasks. This project is not incremental. It’s a foundational step toward autonomous tactical reasoning - starting with the hardest problem in air combat: the dogfight. This is where split-second decisions, energy management, and spatial intuition separate winners from losers. We’re not simulating bureaucracy. We’re simulating survival.

Dogfighting is the ultimate adversarial environment; low latency, high stakes, and no room for error. Yet pilot training remains expensive, logistically constrained, and limited by human availability. Current simulators use scripted AI or canned maneuvers that pilots quickly learn to exploit. That’s not training. That’s theater. This system replaces brittle rules with adaptive intelligence - reinforcement learning agents that evolve, surprise, and push human pilots beyond their limits. 

Built on JSBSim for real aerodynamics and integrated with Azure Machine Learning for scalable training, it turns thousands of simulated engagements into tactical knowledge. If you want to understand how AI will dominate future warfare, start here: where machines learn to fight, not just follow orders.

### Features
✅ Realistic F-16 flight dynamics via JSBSim
✅ OpenAI Gym-compatible reinforcement learning environment
✅ PPO and DQN agent implementations
✅ Azure Machine Learning integration for cloud training
✅ Multi-agent 1v1 and 2v2 dogfight scenarios
✅ Customizable reward functions for tactical behaviors

### Architecture
flowchart TD
    A["(Observation)"] --> B["RL Agent (PPO)"]
    B --> C["(Action)"]
    C --> D["JSBSim Flight Dynamics"]
    D --> E["Reward Calculation"]
    E --> B
    D --> A

 ### Installation & Setup
 git clone https://github.com/BurpingGal/Dogfight-AI-Trainer-Reinforcement-Learning-for-Aerial-Combat-Simulation/tree/main
pip install -r requirements.txt

### Usage
python
import gym
import dogfight_env

env = gym.make('Dogfight-v0')
obs = env.reset()
for _ in range(1000):
    action = env.action_space.sample()
    obs, reward, done, info = env.step(action)
    if done:
        break

### Roadmap
✅4v4 swarm tactics training
✅Azure OpenAI integration for tactical reasoning
✅Real-time visualization dashboard
✅ONNX model export for edge deployment

### Features Implemented

### 🛫 Local AI Trainer
- PPO agent trained with PyTorch
- 17-dimensional observation space:
  - 12 base flight states
  - 4 radar inputs (az, el, rng, closure)
  - 1 missile warning
- Continuous action space: aileron, elevator, rudder, throttle

### 🧠 Tactical Decision Engine
- **BOOM & ZOOM**: Energy fighting at long range
- **TURN FIGHT**: Within visual range dogfight
- **DEFENSIVE SPIRAL**: Evasive maneuver under missile lock
- **SEARCH**: Re-engage or disengage

### 📊 Training
- Reward shaping for tactical behavior
- Model saved as `dogfight_ppo_agent.pth`
- Ready for Azure ML integration

### ☁️ Azure ML Integration 
- Cloud Training
- Log metrics: episode reward, tactic usage
- Save model to cloud registry
- Start with CPU instance for setup
- Later: GPU cluster (`NC6` or `NC4as_T4_v3`) for training
  
Acknowledgements
Credit DBRL, JSBSim, and Microsoft AirSim

