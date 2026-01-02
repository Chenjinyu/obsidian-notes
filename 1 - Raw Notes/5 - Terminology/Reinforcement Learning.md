Date: 2025-10-26
Course:
Tags: [[ML]] [[LLM]] [[Base Knowledge]] [[Terminology]]
Revisit: <% tp.date.now("YYYY-MM-DD", +7) %>

# Content
### 🧠 What is **Reinforcement Learning (RL)?**

**Reinforcement Learning** is a type of machine learning where an **agent** learns how to **interact with an environment** to **maximize rewards** through **trial and error**.

Think of it like **teaching a dog tricks**:

* You give a **treat (reward)** when it performs well.
* Over time, it learns which actions get rewards.

---

### 🔁 How It Works

1. **Agent** – The learner or decision-maker.
2. **Environment** – The world the agent interacts with.
3. **State** – The current situation.
4. **Action** – What the agent can do.
5. **Reward** – Feedback signal from the environment.

```
loop:
    observe state
    take action
    receive reward and new state
    update strategy
```

---

### 🎮 Example: Training a Game AI

| Step   | Description                           |
| ------ | ------------------------------------- |
| State  | Position of player and enemies        |
| Action | Move left, right, jump, shoot         |
| Reward | +1 for killing an enemy, -1 for dying |
| Goal   | Maximize score while staying alive    |

---

### 📈 Types of Reinforcement Learning

| Type             | Description                       | Example         |
| ---------------- | --------------------------------- | --------------- |
| **Model-free**   | Learns directly from experience   | Q-learning, DQN |
| **Model-based**  | Builds a model of the environment | MuZero          |
| **Policy-based** | Learns a policy directly          | PPO, REINFORCE  |
| **Actor-Critic** | Combines policy + value learning  | A3C, DDPG       |

---

### 🤖 Real-World Applications

| Field              | Application                           |
| ------------------ | ------------------------------------- |
| 🕹️ Gaming         | AlphaGo, Dota 2 bot, OpenAI Five      |
| 🚗 Robotics        | Teaching robots to walk, pick objects |
| 💰 Finance         | Algorithmic trading strategies        |
| 🌐 Recommenders    | Dynamic content personalization       |
| ✈️ Control Systems | Self-flying drones, flight simulators |

---

### 🔁 RL vs Supervised Learning

| Feature         | Reinforcement Learning              | Supervised Learning    |
| --------------- | ----------------------------------- | ---------------------- |
| Labels          | No fixed labels, learns from reward | Requires labeled data  |
| Goal            | Learn a strategy (policy)           | Predict correct output |
| Feedback Timing | Delayed (after many actions)        | Immediate (per sample) |

---

### 🧠 TL;DR

> **Reinforcement Learning** is how machines learn from **experience**, improving their actions by maximizing **rewards** in an environment — like training a pet or playing a video game.

---

Would you like to try a Python example using `gym` to see RL in action?



# Note


# Reference

