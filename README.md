<p align="center">
  <img src="https://img.shields.io/badge/Python-3.9%2B-3776AB?style=for-the-badge&logo=python&logoColor=white" alt="Python"/>
  <img src="https://img.shields.io/badge/Pygame-2.x-00979D?style=for-the-badge&logo=python&logoColor=white" alt="Pygame"/>
  <img src="https://img.shields.io/badge/Reinforcement_Learning-Q--Learning-FF6F00?style=for-the-badge" alt="RL"/>
  <img src="https://img.shields.io/badge/License-MIT-green?style=for-the-badge" alt="License"/>
</p>

# 🚦 Smart Traffic Signal Optimization System

> **An intelligent traffic signal control system powered by Q-Learning Reinforcement Learning, with a real-time Pygame simulation that visually demonstrates how RL outperforms traditional fixed-timer signals.**

<p align="center">
  <img width="795" height="799" alt="Screenshot 2026-04-10 at 7 48 54 PM" src="https://github.com/user-attachments/assets/2431bdcf-660e-4330-8c54-10d696462475" />
</p>

---

## 📖 Table of Contents

- [Overview](#-overview)
- [Key Features](#-key-features)
- [Architecture](#-architecture)
- [How It Works](#-how-it-works)
- [Installation](#-installation)
- [Usage](#-usage)
- [Controls](#-controls)
- [Project Structure](#-project-structure)
- [Configuration](#-configuration)
- [Performance Results](#-performance-results)
- [Technologies Used](#-technologies-used)
- [Contributing](#-contributing)
- [License](#-license)

---

## 🎯 Overview

Urban traffic congestion is a growing global challenge. Traditional fixed-timer traffic signals operate on static cycles regardless of actual traffic conditions, leading to unnecessary delays and increased emissions.

This project implements a **Q-Learning-based Reinforcement Learning agent** that learns to dynamically control traffic signals at a 4-way intersection. The agent observes the number of waiting vehicles in each direction and learns an optimal signal-switching policy that minimizes overall wait times.

A **real-time Pygame simulation** provides visual feedback, and a **fixed-timer baseline** is included for direct performance comparison — making this project ideal for **academic presentations**, **research demonstrations**, and **portfolio showcases**.

---

## ✨ Key Features

| Feature | Description |
|---------|-------------|
| **🤖 Q-Learning Agent** | Tabular Q-learning with ε-greedy exploration, automatic epsilon decay, and continuous online training |
| **⏱ Fixed-Timer Baseline** | Traditional signal controller for A/B comparison — toggle in real time |
| **🟢🟡🔴 Realistic Signal Phases** | Full Green → Yellow → Red transition cycle with clearance intervals to prevent intersection collisions |
| **🚗 Car-Following Model** | Vehicles maintain safe following distances — no rear-end collisions |
| **📊 Live Dashboard** | Real-time display of mode, signal state, waiting cars, average wait, Q-table size, and epsilon |
| **🏷 Per-Lane Counters** | Floating badges on each road approach showing total and waiting car counts |
| **📈 Performance Plotting** | Matplotlib chart (saved as PNG) comparing RL vs Fixed-timer upon exit |
| **🎮 Interactive Controls** | Toggle modes, reset simulation, and quit — all via keyboard |
| **🎨 Premium Visuals** | Dark theme, dashed lane markings, crosswalks, car shadows, windshields, headlights, glowing signals |

---

## 🏗 Architecture

```
┌─────────────┐     ┌──────────────────┐     ┌─────────────────┐
│   main.py   │────▶│  environment.py  │────▶│  traffic_signal  │
│  (Pygame    │     │  (State/Reward/  │     │  (Phase mgmt,   │
│   loop &    │     │   Spawning)      │     │   Yellow light)  │
│   UI)       │     └──────────────────┘     └─────────────────┘
└─────────────┘              │
       │                     ▼
       │            ┌──────────────────┐
       │            │     car.py       │
       │            │  (Movement,      │
       │            │   Stop logic,    │
       │            │   Rendering)     │
       │            └──────────────────┘
       │
       ▼
┌─────────────┐     ┌──────────────────┐
│  agent.py   │     │    utils.py      │
│  (Q-table,  │     │  (Constants,     │
│   ε-greedy, │     │   Colors,        │
│   Learning) │     │   Geometry)      │
└─────────────┘     └──────────────────┘
```

---

## 🧠 How It Works

### State Representation
The environment state is a **4-tuple** of discretized waiting-car counts:
```
State = (N_waiting, S_waiting, E_waiting, W_waiting)
```
Each value is capped at 5, yielding a manageable state space of 6⁴ = 1,296 possible states.

### Actions
| Action | Effect |
|--------|--------|
| `0` | Give **green** to the North-South corridor |
| `1` | Give **green** to the East-West corridor |

### Reward Function
```
Reward = −(total waiting cars) − penalty × (signal switched)
```
- **Negative waiting count** incentivizes the agent to reduce congestion.
- **Switch penalty** (default: 2) discourages unnecessary signal toggling.

### Yellow Clearance Phase
When the agent switches the signal, the system transitions through a **1.5-second yellow phase** (45 frames at 30 FPS). During yellow, **no direction has green**, allowing cars already in the intersection to safely clear before cross-traffic proceeds.

### Learning Algorithm
Standard **Q-Learning** update:
```
Q(s, a) ← Q(s, a) + α × [r + γ × max_a' Q(s', a') − Q(s, a)]
```

| Hyperparameter | Default | Description |
|----------------|---------|-------------|
| α (alpha) | 0.10 | Learning rate |
| γ (gamma) | 0.95 | Discount factor |
| ε (epsilon) | 1.0 → 0.05 | Exploration rate with multiplicative decay (0.9995/step) |

---

## 🚀 Installation

### Prerequisites
- **Python 3.9+**

### Steps

```bash
# 1. Clone the repository
git clone https://github.com/jayashish05/Smart-Traffic-Signal-Optimization-System.git
cd Smart-Traffic-Signal-Optimization-System

# 2. (Optional) Create a virtual environment
python3 -m venv venv
source venv/bin/activate        # macOS/Linux
# venv\Scripts\activate         # Windows

# 3. Install dependencies
pip install pygame numpy matplotlib
```

> **Note:** Only three external packages are required — `pygame`, `numpy`, and `matplotlib`.

---

## 🎮 Usage

```bash
python3 main.py
```

The simulation window (800×800) will open immediately.  
The RL agent begins training continuously from the first frame.

---

## ⌨ Controls

| Key | Action |
|-----|--------|
| `SPACE` | Toggle between **RL Agent** and **Fixed Timer** modes |
| `R` | **Reset** the simulation (clears all cars, resets episode) |
| `ESC` | **Quit** — saves performance comparison chart and displays it |

---

## 📁 Project Structure

```
Smart-Traffic-Signal-Optimization-System/
│
├── main.py              # Entry point: Pygame loop, road/car rendering, UI overlay
├── environment.py       # RL environment: state, reward, car spawning, yellow transitions
├── agent.py             # Q-learning agent: ε-greedy policy, Q-table, training
├── car.py               # Vehicle class: movement, stop-line logic, car-following, rendering
├── traffic_signal.py    # Signal management: 4-state phase machine, fixed-timer controller
├── utils.py             # Constants: colors, geometry, spawn configs, helpers
├── README.md            # This file
├── .gitignore           # Python/Pygame ignores
└── assets/              # Screenshots & demo media
    └── demo_screenshot.png
```

---

## ⚙ Configuration

Key simulation parameters can be tuned in `utils.py`:

| Parameter | Default | Description |
|-----------|---------|-------------|
| `FPS` | 30 | Simulation frame rate |
| `ROAD_WIDTH` | 120 | Total road width in pixels (2 lanes) |
| `CAR_SPEED` | 3 | Pixels per frame |
| `SPAWN_PROB` | 0.025 | Per-direction spawn probability per frame |
| `DECISION_INTERVAL` | 150 | Frames between RL decisions (~5 s) |
| `MAX_CARS_PER_DIR` | 5 | State discretization cap |
| `SWITCH_PENALTY` | 2 | Reward penalty for changing signal phase |
| `MIN_GAP` | 8 | Minimum bumper-to-bumper gap (pixels) |

Agent hyperparameters can be tuned in `agent.py`:

| Parameter | Default | Description |
|-----------|---------|-------------|
| `alpha` | 0.1 | Learning rate |
| `gamma` | 0.95 | Discount factor |
| `epsilon` | 1.0 | Initial exploration rate |
| `epsilon_min` | 0.05 | Minimum exploration rate |
| `epsilon_decay` | 0.9995 | Multiplicative decay per decision step |

---

## 📈 Performance Results

Upon pressing **ESC**, the simulation generates a `performance_comparison.png` chart comparing the **average waiting cars per episode** between the RL agent and the fixed-timer baseline.

After sufficient training episodes, the RL agent typically achieves:
- **20–40% reduction** in average waiting vehicles compared to the fixed timer
- More adaptive signal timing during asymmetric traffic load scenarios
- Faster intersection clearance during peak spawns

---

## 🛠 Technologies Used

| Technology | Purpose |
|------------|---------|
| **Python 3** | Core programming language |
| **Pygame** | Real-time simulation rendering and event handling |
| **NumPy** | Numerical support |
| **Matplotlib** | Performance visualization and chart generation |
| **Q-Learning** | Reinforcement learning algorithm for signal optimization |

---

## 🤝 Contributing

Contributions are welcome! To contribute:

1. **Fork** the repository
2. Create a **feature branch** (`git checkout -b feature/amazing-feature`)
3. **Commit** your changes (`git commit -m 'Add amazing feature'`)
4. **Push** to the branch (`git push origin feature/amazing-feature`)
5. Open a **Pull Request**

### Ideas for extension:
- Deep Q-Network (DQN) for continuous state spaces
- Multi-intersection coordination
- Turn lanes and pedestrian crossings
- Variable speed vehicles and emergency vehicle priority
- Real-world traffic data integration

---

## 📄 License

This project is licensed under the **MIT License** — see the [LICENSE](LICENSE) file for details.

---

<p align="center">
  <b>⭐ If you found this project useful, please give it a star! ⭐</b>
</p>

<p align="center">
  Made with ❤️ by <a href="https://github.com/jayashish05">Jayashish</a>
</p>
