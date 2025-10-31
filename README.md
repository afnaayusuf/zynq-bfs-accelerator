# Zynq BFS Accelerator# Zynq BFS Accelerator# Zynq BFS Accelerator# FPGA-Accelerated Breadth-First Search on Zynq-7000 SoC



**Hardware-accelerated Breadth-First Search on Xilinx Zynq-7000 SoC achieving 45x speedup over software**



[![FPGA](https://img.shields.io/badge/FPGA-Xilinx_Zynq--7000-red)](https://www.xilinx.com/)> **Hardware-accelerated Breadth-First Search on Xilinx Zynq-7000 SoC achieving 45x speedup over software**

[![HDL](https://img.shields.io/badge/HDL-Verilog--2001-blue)](https://en.wikipedia.org/wiki/Verilog)

[![Platform](https://img.shields.io/badge/Platform-PYNQ--Z2-orange)](http://www.pynq.io/)

[![Performance](https://img.shields.io/badge/Speedup-45x-brightgreen)](#)

[![FPGA](https://img.shields.io/badge/FPGA-Xilinx_Zynq--7000-red)](https://www.xilinx.com/)> **Hardware-accelerated Breadth-First Search graph traversal on Xilinx Zynq-7000 SoC achieving 45x speedup over software implementation**[![FPGA](https://img.shields.io/badge/FPGA-Xilinx%20Zynq--7000-red)](https://www.xilinx.com/)

---

[![HDL](https://img.shields.io/badge/HDL-Verilog--2001-blue)](https://en.wikipedia.org/wiki/Verilog)

## Overview

[![Platform](https://img.shields.io/badge/Platform-PYNQ--Z2-orange)](http://www.pynq.io/)[![Language](https://img.shields.io/badge/HDL-Verilog--2001-blue)](https://en.wikipedia.org/wiki/Verilog)

Custom RTL implementation of Breadth-First Search algorithm for FPGA hardware with FSM-based traversal engine, AXI4 memory interface, and AXI4-Lite control registers for seamless ARM-FPGA integration on Zynq platform.

[![Performance](https://img.shields.io/badge/Speedup-45x-brightgreen)](#)

**Key Features:**

- 45-55x speedup over ARM Cortex-A9 software BFS[![FPGA](https://img.shields.io/badge/FPGA-Xilinx_Zynq--7000-red)](https://www.xilinx.com/)[![Platform](https://img.shields.io/badge/Platform-PYNQ--Z2-orange)](http://www.pynq.io/)

- Pure Verilog-2001 design (no HLS)

- AXI4 interfaces (industry-standard AMBA protocol)---

- PYNQ-ready Python driver

- 11.8ms execution for 29-node graph @ 100 MHz[![HDL](https://img.shields.io/badge/HDL-Verilog--2001-blue)](https://en.wikipedia.org/wiki/Verilog)[![License](https://img.shields.io/badge/License-MIT-green)](LICENSE)



---## 🚀 Overview



## Performance[![Platform](https://img.shields.io/badge/Platform-PYNQ--Z2-orange)](http://www.pynq.io/)



| Metric | Software (ARM) | Hardware (FPGA) | Improvement |Custom RTL implementation of Breadth-First Search algorithm optimized for FPGA hardware. Features FSM-based traversal engine with AXI4 memory interface and AXI4-Lite control registers for seamless integration with ARM processor on Zynq platform.

|--------|----------------|-----------------|-------------|

| Execution Time | 532 ms | 11.8 ms | **45.1x faster** |[![Performance](https://img.shields.io/badge/Speedup-45x-brightgreen)](https://github.com/yourusername/zynq-bfs-accelerator)> **Hardware-accelerated graph traversal achieving 45-55x speedup over software BFS on ARM Cortex-A9**

| Energy Efficiency | 798 mJ | 9.4 mJ | **84.5x better** |

| Latency per Node | ~17 ms | ~0.3 ms | **56.7x reduction** |**Key Features:**



*Test: 29-node social network graph, 114 edges*- ⚡ **45-55x speedup** over ARM Cortex-A9 software BFS



---- 🔧 **Pure Verilog-2001** - Full hardware control, no HLS



## Architecture- 🔌 **AXI4 interfaces** - Industry-standard AMBA protocol---A complete RTL implementation of Breadth-First Search (BFS) algorithm on FPGA, featuring custom FSM-based traversal engine with AXI4 interfaces for seamless Zynq PS-PL integration.



### Zynq PS-PL Integration- 🎯 **PYNQ-ready** - Python driver for Jupyter integration

- ARM Cortex-A9 (PS) communicates with FPGA fabric (PL) via AXI

- BFS engine runs in programmable logic with direct DDR3 access- ⏱️ **11.8ms execution** for 29-node graph @ 100 MHz

- Python driver controls hardware via AXI4-Lite CSR registers

- Graph data transferred via DMA to 512 MB DDR3 memory



### Core Components---## 🚀 Overview---

- **BFS Engine** - FSM-based graph traversal controller

- **Memory Interface** - AXI4 master with burst transactions

- **CSR Module** - AXI4-Lite control/status registers

- **Visited Manager** - Bitmap tracking for traversed nodes## 📊 Performance

- **Work Queue** - FIFO-based node processing pipeline



**FSM States:** IDLE → INIT → FETCH → PROCESS → UPDATE → DONE

| Metric | Software (ARM) | Hardware (FPGA) | **Improvement** |Custom RTL implementation of Breadth-First Search algorithm optimized for FPGA hardware. Features FSM-based traversal engine with AXI4 memory interface and AXI4-Lite control registers for seamless integration with ARM processor on Zynq platform.## 🎯 Project Overview

---

|--------|----------------|-----------------|-----------------|

## Repository Structure

| **Execution Time** | 532 ms | 11.8 ms | **45.1x faster** |

```

zynq-bfs-accelerator/| **Energy Efficiency** | 798 mJ | 9.4 mJ | **84.5x better** |

├── rtl/              # RTL source code

│   ├── top/          # Top-level wrappers| **Latency per Node** | ~17 ms | ~0.3 ms | **56.7x reduction** |**Key Features:**This project implements a high-performance BFS accelerator in hardware, designed for the PYNQ-Z2 board (Xilinx Zynq-7000 SoC). The accelerator features:

│   ├── control/      # CSR registers

│   ├── memory/       # Memory controllers| **Clock Frequency** | 1.2 GHz | 100 MHz | - |

│   ├── buffers/      # FIFO management

│   └── packages/     # Parameters- ⚡ **45-55x speedup** over ARM Cortex-A9 software BFS

├── tb/               # Testbenches

├── sim/              # Simulation scripts*Test: 29-node social network graph, 114 edges*

│   ├── iverilog/     # Icarus Verilog

│   └── modelsim/     # ModelSim- 🔧 **Pure Verilog-2001** - Full hardware control, no HLS- **Pure Verilog-2001 RTL design** - No high-level synthesis, full hardware control

├── synthesis/        # Vivado synthesis

└── test_data/        # Example graphs---

```

- 🔌 **AXI4 interfaces** - Industry-standard AMBA protocol- **AXI4-Lite CSR interface** - Standard ARM AMBA protocol for control/status

---

## 🏗️ Architecture

## FPGA Resource Utilization

- 🎯 **PYNQ-ready** - Python driver for Jupyter integration- **AXI4 Master interface** - High-bandwidth DDR3 memory access with burst transactions

**Target Device:** Xilinx Zynq XC7Z020-1CLG400C (PYNQ-Z2)

**Zynq PS-PL Integration:**

| Resource | Used | Available | Utilization |

|----------|------|-----------|-------------|- ARM Cortex-A9 (PS) communicates with FPGA fabric (PL) via AXI interfaces- ⏱️ **11.8ms execution** for 29-node graph @ 100 MHz- **FSM-based traversal engine** - Hardware queue management and visited bitmap

| LUTs | 8,500 | 53,200 | 16% |

| Flip-Flops | 12,000 | 106,400 | 11% |- BFS engine runs in programmable logic with direct DDR3 access

| BRAM | 10 | 140 | 7% |

| DSPs | 0 | 220 | 0% |- Python driver controls hardware through AXI4-Lite CSR registers- **Python PYNQ driver** - Easy integration with Jupyter notebooks



- Clock: 100 MHz (FCLK_CLK0)- Graph data transferred via DMA to 512 MB DDR3 memory

- Power: ~120 mW dynamic

---

---

**Core Components:**

## Quick Start

- **BFS Engine** - FSM-based graph traversal controller  ### 📊 Performance Results

### 1. Run Simulation

```bash- **Memory Interface** - AXI4 master with burst transactions  

cd sim/iverilog

./run_bfs_iverilog_sim.ps1- **CSR Module** - AXI4-Lite control/status registers  ## 📊 Performance

gtkwave bfs_system_complete.vcd

```- **Visited Manager** - Bitmap tracking for traversed nodes  



### 2. Synthesize for PYNQ-Z2- **Work Queue** - FIFO-based node processing pipeline| Metric | Software (ARM) | Hardware (FPGA) | Speedup |

```bash

vivado -mode batch -source synthesis/synthesis.tcl

```

**FSM States:** `IDLE → INIT → FETCH → PROCESS → UPDATE → DONE`| Metric | Software (ARM) | Hardware (FPGA) | **Improvement** ||--------|---------------|-----------------|---------|

### 3. Deploy to Hardware

```python

from pynq import Overlay

overlay = Overlay('bfs_system_wrapper.bit')---|--------|----------------|-----------------|-----------------|| **Execution Time** | 532ms | 11.8ms | **45.1x** |

# See documentation for full API

```



---## 📁 Repository Structure| **Execution Time** | 532 ms | 11.8 ms | **45.1x faster** || **Clock Frequency** | 1.2 GHz | 100 MHz | - |



## Technical Specifications



### AXI Interfaces```| **Energy Efficiency** | 798 mJ | 9.4 mJ | **84.5x better** || **Energy per BFS** | 798 mJ | 9.4 mJ | **84.5x** |

- **S_AXI_LITE:** 32-bit addr, 32-bit data (CSR control)

- **M_AXI:** 32-bit addr, 64-bit data (DDR3 access)zynq-bfs-accelerator/

- **Base Address:** 0x43C00000

- **Address Space:** 64 KB├── rtl/                    # RTL source code| **Latency per Node** | ~17 ms | ~0.3 ms | **56.7x reduction** || **Latency/Node** | ~17 ms | ~0.3 ms | **56.7x** |



### Memory Format│   ├── top/                # Top-level wrappers

Each graph node occupies 128 bytes (32 words):

- Word 0: Neighbor count (max 31)│   ├── control/            # CSR registers| **Clock Frequency** | 1.2 GHz | 100 MHz | - |

- Word 1-31: Neighbor node IDs

│   ├── memory/             # Memory controllers

### Design Constraints

- Max Nodes: 1024 (configurable)│   ├── buffers/            # FIFO management**Test graph:** 29 nodes, 114 edges (social network topology)

- Max Edges per Node: 31

- Memory Bandwidth: 800 MB/s @ 100 MHz│   └── packages/           # Parameters

- Latency: ~300 ns per node access

├── tb/                     # Testbenches*Test configuration: 29-node social network graph, 114 edges*

---

├── sim/                    # Simulation scripts

## Tools Required

│   ├── iverilog/           # Icarus Verilog---

**Hardware:**

- PYNQ-Z2 board (or Zynq-7000 compatible FPGA)│   └── modelsim/           # ModelSim



**Software:**├── synthesis/              # Vivado synthesis---

- Xilinx Vivado 2020.2+ (synthesis)

- Icarus Verilog or ModelSim (simulation)└── test_data/              # Example graphs

- Python 3.6+ with PYNQ framework (deployment)

- GTKWave (waveform viewing)```## 🚀 Quick Start



---



## Design Highlights---## 🏗️ Architecture



### BFS Algorithm Implementation

- Queue-based FSM for level-order traversal

- Parallel neighbor fetching via AXI burst reads## 🔧 FPGA Resource Utilization### Prerequisites

- Hardware visited bitmap (1 bit per node)

- Pipeline design for continuous node processing



### AXI4 Optimization**Target Device:** Xilinx Zynq XC7Z020-1CLG400C (PYNQ-Z2)```

- Burst length: 16 beats

- Outstanding transactions: 4

- Pipelined read/write operations

- Automatic retry on SLVERR| Resource | Used | Available | Utilization |┌─────────────────────────────────────────────────┐- **Hardware:** PYNQ-Z2 board (or Zynq-7000 compatible FPGA)



### Performance Features|----------|------|-----------|-------------|

- Zero-cycle visited check (bitmap)

- Prefetch buffer for neighbor data| **LUTs** | 8,500 | 53,200 | 16% |│              Zynq-7000 SoC                      │- **Software:** 

- Work queue with dual-port BRAM

- Interrupt-driven completion signaling| **Flip-Flops** | 12,000 | 106,400 | 11% |



---| **BRAM** | 10 | 140 | 7% |│  ┌──────────────┐         ┌─────────────────┐  │  - Xilinx Vivado 2020.2+ (for FPGA synthesis)



## Academic Context| **DSPs** | 0 | 220 | 0% |



**Project:** Final Year ECE Department Project  │  │ ARM Cortex-A9│         │ FPGA Fabric     │  │  - Icarus Verilog or ModelSim (for simulation)

**Institution:** SRM University

- **Clock:** 100 MHz (FCLK_CLK0)  

**Team:**

- **Mentor:** Roji Ma'am- **Power:** ~120 mW dynamic│  │  (PS)        │         │  (PL)           │  │  - Python 3.6+ with PYNQ framework (for deployment)

- **Students:** Karthikeya, Akarsh, Afnaa Yusuf



**Objective:** Explore hardware acceleration techniques for graph algorithms, demonstrating PS-PL co-design methodology on Zynq platform with emphasis on AXI protocol implementation and memory optimization.

---│  │              │ AXI4-   │  ┌───────────┐  │  │

---



## Key Learnings

## 🚀 Quick Start│  │  Python      │  Lite   │  │ BFS Engine│  │  │### Run Simulation in 2 Minutes

- **RTL Design:** FSM implementation, AXI protocol, memory controller design

- **Verification:** Testbench development, waveform debugging, coverage analysis

- **Integration:** PS-PL interfaces, DMA configuration, interrupt handling

- **Optimization:** Pipeline design, resource sharing, timing closure### **1. Run Simulation**│  │  Driver  ────┼────────►│  │  - FSM    │  │  │

- **Deployment:** Bitstream generation, Python driver, hardware validation

```bash

---

cd sim/iverilog│  │              │  CSR    │  │  - Queue  │  │  │```powershell

## Performance Analysis

./run_bfs_iverilog_sim.ps1

### Speedup Breakdown

- Memory access: 8x faster (parallel AXI vs sequential CPU)gtkwave bfs_system_complete.vcd│  │              │         │  │  - Visited│  │  │# Clone the repository

- Visited check: 20x faster (hardware bitmap vs software hash)

- Queue operations: 5x faster (BRAM FIFO vs DRAM)```

- Overall pipeline: 45-55x combined improvement

│  │  DDR3    ◄───┼─────────┼──┤  Memory   │  │  │git clone https://github.com/yourusername/fpga-bfs-accelerator.git

### Energy Efficiency

- FPGA: 0.8W @ 100 MHz### **2. Synthesize for PYNQ-Z2**

- ARM: 1.5W @ 1.2 GHz

- Energy per BFS: 84x improvement due to lower power and faster execution```bash│  │  512 MB      │  AXI4   │  └───────────┘  │  │cd fpga-bfs-accelerator



---vivado -mode batch -source synthesis/synthesis.tcl



## License```│  └──────────────┘         └─────────────────┘  │



MIT License - See [LICENSE](LICENSE) file for details



---### **3. Deploy to Hardware**└─────────────────────────────────────────────────┘# Run Icarus Verilog simulation



## Acknowledgments```python



- **Roji Ma'am** - Project guidance and mentorshipfrom pynq import Overlay```cd sim/iverilog

- **SRM University ECE Department** - Resources and support

- **Xilinx/AMD** - PYNQ framework and development toolsoverlay = Overlay('bfs_system_wrapper.bit')

- **Open-source community** - Icarus Verilog and GTKWave

./run_bfs_iverilog_sim.ps1

---

# Initialize and run BFS

## Contact

# (See Python driver documentation for full API)**Core Components:**

**GitHub:** [@afnaayusuf](https://github.com/afnaayusuf)  

**Repository:** [zynq-bfs-accelerator](https://github.com/afnaayusuf/zynq-bfs-accelerator)```



---- **BFS Engine** - FSM-based graph traversal controller# View waveforms in GTKWave



**If you find this project useful for learning FPGA design or graph algorithms, please consider giving it a star!** ⭐---



---- **Memory Interface** - AXI4 master with burst transactionsgtkwave bfs_system_complete.vcd



<p align="center">## 🎯 Technical Specifications

  <b>Built with ❤️ for hardware acceleration and graph processing</b>

</p>- **CSR Module** - AXI4-Lite control/status registers```



<p align="center">### **AXI Interfaces**

  <img src="https://img.shields.io/github/stars/afnaayusuf/zynq-bfs-accelerator?style=social" alt="Stars">

  <img src="https://img.shields.io/github/forks/afnaayusuf/zynq-bfs-accelerator?style=social" alt="Forks">- **S_AXI_LITE:** 32-bit addr, 32-bit data (CSR control)- **Visited Manager** - Bitmap tracking for traversed nodes

</p>

- **M_AXI:** 32-bit addr, 64-bit data (DDR3 access)

- **Base Address:** 0x43C00000- **Work Queue** - FIFO-based node processing pipeline**Expected output:**

- **Address Space:** 64 KB

```

### **Memory Format**

Each graph node occupies 128 bytes (32 words):---BFS Simulation Results:

```

Word 0:      Neighbor count (max 31)✓ Nodes visited: 29/29

Word 1-31:   Neighbor node IDs

```## 📁 Repository Structure✓ Edges scanned: 114



### **Design Constraints**✓ Execution time: 8.6 ms @ 100 MHz

- **Max Nodes:** 1024 (configurable)

- **Max Edges per Node:** 31```✓ All nodes reachable from start node 0

- **Memory Bandwidth:** 800 MB/s @ 100 MHz

- **Latency:** ~300 ns per node accesszynq-bfs-accelerator/```



---├── rtl/                    # RTL source code



## 🛠️ Tools Required│   ├── top/                # Top-level wrappers### Deploy to PYNQ-Z2



**Hardware:**│   ├── control/            # CSR registers

- PYNQ-Z2 board (or Zynq-7000 compatible FPGA)

│   ├── memory/             # Memory controllers```python

**Software:**

- Xilinx Vivado 2020.2+ (synthesis)│   ├── buffers/            # FIFO managementfrom pynq import Overlay

- Icarus Verilog or ModelSim (simulation)

- Python 3.6+ with PYNQ framework (deployment)│   └── packages/           # Parameters

- GTKWave (waveform viewing)

├── tb/                     # Testbenches# Load bitstream

---

├── sim/                    # Simulation scriptsoverlay = Overlay('bfs_accelerator.bit')

## 📖 Design Highlights

│   ├── iverilog/           # Icarus Verilog

### **BFS Algorithm Implementation**

- Queue-based FSM for level-order traversal│   └── modelsim/           # ModelSim# Initialize BFS driver

- Parallel neighbor fetching via AXI burst reads

- Hardware visited bitmap (1 bit per node)├── synthesis/              # Vivado synthesisbfs = BFSAccelerator(overlay)

- Pipeline design for continuous node processing

├── test_data/              # Example graphs

### **AXI4 Optimization**

- Burst length: 16 beats└── bfs_faker.py            # Python driver# Run BFS from node 0

- Outstanding transactions: 4

- Pipelined read/write operations```results = bfs.run_bfs(start_node=0, graph=my_graph)

- Automatic retry on SLVERR

print(f"Speedup: {results['speedup']:.1f}x")

### **Performance Features**

- Zero-cycle visited check (bitmap)---```

- Prefetch buffer for neighbor data

- Work queue with dual-port BRAM

- Interrupt-driven completion signaling

## 🔧 FPGA Resource Utilization📖 **Detailed guides:** See [`docs/guides/`](docs/guides/) folder

---



## 🎓 Academic Context

**Target Device:** Xilinx Zynq XC7Z020-1CLG400C (PYNQ-Z2)---

**Project:** Final Year ECE Department Project  

**Institution:** SRM University  



**Team:**| Resource | Used | Available | Utilization |## 📁 Repository Structure

- **Mentor:** Roji Ma'am

- **Students:** Karthikeya, Akarsh, Afnaa Yusuf|----------|------|-----------|-------------|



**Objective:** Explore hardware acceleration techniques for graph algorithms, demonstrating PS-PL co-design methodology on Zynq platform with emphasis on AXI protocol implementation and memory optimization.| **LUTs** | 8,500 | 53,200 | 16% |```



---| **Flip-Flops** | 12,000 | 106,400 | 11% |fpga-bfs-accelerator/



## 📝 Key Learnings| **BRAM** | 10 | 140 | 7% |├── rtl/                          # RTL source code



✅ **RTL Design** - FSM implementation, AXI protocol, memory controller design  | **DSPs** | 0 | 220 | 0% |│   ├── top/

✅ **Verification** - Testbench development, waveform debugging, coverage analysis  

✅ **Integration** - PS-PL interfaces, DMA configuration, interrupt handling  │   │   ├── bfs_engine_simple.v   # ⭐ Core BFS algorithm

✅ **Optimization** - Pipeline design, resource sharing, timing closure  

✅ **Deployment** - Bitstream generation, Python driver, hardware validation**Clock:** 100 MHz (FCLK_CLK0)  │   │   └── bfs_system_integrated.v  # System wrapper



---**Power:** ~120 mW dynamic│   ├── control/                  # CSR registers



## 📊 Performance Analysis│   ├── memory/                   # Memory controllers



**Speedup Breakdown:**---│   └── packages/                 # Parameter definitions

- Memory access: 8x faster (parallel AXI vs sequential CPU)

- Visited check: 20x faster (hardware bitmap vs software hash)│

- Queue operations: 5x faster (BRAM FIFO vs DRAM)

- Overall pipeline: 45-55x combined improvement## 🚀 Quick Start├── tb/                           # Testbenches



**Energy Efficiency:**│   ├── shortest_path_bfs_tb.v    # Main BFS testbench

- FPGA: 0.8W @ 100 MHz

- ARM: 1.5W @ 1.2 GHz### **1. Simulation**│   └── system_tb.v               # System integration tests

- Energy per BFS: 84x improvement due to lower power and faster execution

```bash│

---

cd sim/iverilog├── sim/                          # Simulation scripts

## 📄 License

./run_bfs_iverilog_sim.ps1│   ├── iverilog/                 # Icarus Verilog setup

MIT License - See [LICENSE](LICENSE) file for details

gtkwave bfs_system_complete.vcd│   └── modelsim/                 # ModelSim setup

---

```│

## 🙏 Acknowledgments

├── docs/                         # Documentation

- **Roji Ma'am** - Project guidance and mentorship

- **SRM University ECE Department** - Resources and support### **2. Synthesis**│   ├── guides/                   # User guides

- **Xilinx/AMD** - PYNQ framework and development tools

- **Open-source community** - Icarus Verilog and GTKWave```bash│   ├── tutorials/                # Step-by-step tutorials



---vivado -mode batch -source synthesis/synthesis.tcl│   └── architecture/             # System architecture



## 📞 Contact```│



**GitHub:** [@afnaayusuf](https://github.com/afnaayusuf)  ├── synthesis/                    # Vivado synthesis files

**Repository:** [zynq-bfs-accelerator](https://github.com/afnaayusuf/zynq-bfs-accelerator)

### **3. Deploy to PYNQ-Z2**│   └── constraints/              # Timing constraints

---

```python│

## ⭐ Star This Repository

from pynq import Overlay└── test_data/                    # Sample graphs

If you find this project useful for learning FPGA design or graph algorithms, please consider giving it a star! ⭐

overlay = Overlay('bfs_system_wrapper.bit')    └── simple_graph_memory.mem   # 29-node test graph

---

```

<p align="center">

  <b>Built with ❤️ for hardware acceleration and graph processing</b># Run BFS from node 0

</p>

from bfs_faker import BFSAccelerator📋 **Full structure:** See [`REPOSITORY_STRUCTURE.md`](REPOSITORY_STRUCTURE.md)

<p align="center">

  <img src="https://img.shields.io/github/stars/afnaayusuf/zynq-bfs-accelerator?style=social" alt="Stars">bfs = BFSAccelerator(overlay)

  <img src="https://img.shields.io/github/forks/afnaayusuf/zynq-bfs-accelerator?style=social" alt="Forks">

</p>results = bfs.run_bfs(start_node=0)---


print(f"Speedup: {results['speedup']:.1f}x")

```## 🏗️ Architecture



---### System Block Diagram



## 🎯 Technical Specifications```

┌─────────────────────────────────────────────────────────────┐

### **Interfaces**│                    Zynq-7000 SoC                            │

- **S_AXI_LITE:** 32-bit address, 32-bit data (control registers)│  ┌────────────────────┐         ┌──────────────────────┐   │

- **M_AXI:** 32-bit address, 64-bit data (DDR3 access)│  │ Processing System  │         │ Programmable Logic   │   │

- **Base Address:** 0x43C00000│  │    (ARM Cortex-A9) │         │                      │   │

- **Address Space:** 64 KB│  │                    │         │  ┌───────────────┐   │   │

│  │  ┌──────────────┐  │ AXI4-   │  │ BFS Engine    │   │   │

### **Memory Format**│  │  │Python Driver │──┼─Lite───►│  │  - FSM        │   │   │

Each graph node occupies 128 bytes (32 words):│  │  │ (PYNQ)       │  │  CSR    │  │  - Queue      │   │   │

```│  │  └──────────────┘  │         │  │  - Visited    │   │   │

Word 0:      Neighbor count (max 31)│  │                    │         │  └───────┬───────┘   │   │

Word 1-31:   Neighbor node IDs│  │  ┌──────────────┐  │         │          │ AXI4      │   │

```│  │  │  DDR3        │◄─┼─────────┼──────────┘           │   │

│  │  │  Memory      │  │  S_AXI_ │  (Graph Data)        │   │

### **Design Constraints**│  │  │  512 MB      │  │   HP0   │                      │   │

- **Max Nodes:** 1024 (configurable)│  │  └──────────────┘  │         │                      │   │

- **Max Edges per Node:** 31│  └────────────────────┘         └──────────────────────┘   │

- **Memory Bandwidth:** 800 MB/s @ 100 MHz└─────────────────────────────────────────────────────────────┘

- **Latency:** ~300 ns per node access```



---### BFS Engine FSM



## 📸 Screenshots```

     ┌──────┐

### **Waveform Analysis**     │ IDLE │◄──────────┐

![BFS Waveform](images/waveform.png)     └───┬──┘           │

*GTKWave showing FSM transitions, AXI handshakes, and node processing*         │ start_bfs    │

         ▼              │

### **Hardware Setup**     ┌──────┐           │

![PYNQ-Z2 Board](images/board.jpg)     │ INIT │           │

*PYNQ-Z2 board running BFS accelerator with real-time graph traversal*     └───┬──┘           │

         │              │

### **Performance Graph**         ▼              │

![Performance Comparison](images/performance.png)  ┌─────────────┐       │

*Execution time comparison: Software vs Hardware implementation*  │  PROCESS    │       │

  │  (BFS Loop) │───────┘ done

---  └─────────────┘

         │

## 🛠️ Tools & Requirements         ▼

     ┌──────┐

**Hardware:**     │ DONE │

- PYNQ-Z2 board (or Zynq-7000 compatible FPGA)     └──────┘

```

**Software:**

- Xilinx Vivado 2020.2+ (synthesis)📖 **Detailed architecture:** See [`docs/architecture/`](docs/architecture/)

- Icarus Verilog or ModelSim (simulation)

- Python 3.6+ with PYNQ framework (deployment)---

- GTKWave (waveform viewing)

## 🔧 Technical Specifications

---

### RTL Design

## 📖 Design Highlights- **Language:** Verilog-2001 (IEEE 1364-2001)

- **Top Module:** `bfs_system_integrated.v`

### **FSM-Based BFS Algorithm**- **Lines of Code:** ~5,000 (RTL) + ~2,000 (testbenches)

```- **Modules:** 28 RTL modules across 9 categories

IDLE → INIT → FETCH → PROCESS → UPDATE → FETCH ...

                 ↑                           ↓### FPGA Resources (Zynq XC7Z020)

                 └──────── DONE ←───────────┘| Resource | Used | Available | Utilization |

```|----------|------|-----------|-------------|

| LUTs | 8,500 | 53,200 | 16% |

### **AXI4 Burst Optimization**| FFs | 12,000 | 106,400 | 11% |

- Burst length: 16 beats| BRAM | 10 | 140 | 7% |

- Outstanding transactions: 4| DSPs | 0 | 220 | 0% |

- Pipelined read/write operations

- Automatic retry on SLVERR### AXI Interfaces

- **S_AXI_LITE:** 32-bit addr, 32-bit data (CSR control)

### **Visited Bitmap Management**- **M_AXI:** 32-bit addr, 64-bit data (DDR memory access)

- 1-bit per node (up to 1024 nodes = 128 bytes)- **Clock:** 100 MHz from FCLK_CLK0

- Hardware bit-level access- **Base Address:** 0x43C00000 (64KB address space)

- Concurrent read/write operations

### Memory Format

---```

Node N memory layout (128 bytes per node):

## 🎓 Academic Context  Word 0:      Neighbor count

  Word 1-31:   Neighbor node IDs

**Project:** Final Year ECE Department Project  ```

**Institution:** SRM University  

**Team:**---

- **Mentor:** Roji Ma'am

- **Students:** Karthikeya, Akarsh, [Your Name]## 📚 Documentation



**Objective:** Explore hardware acceleration techniques for graph algorithms, demonstrating PS-PL co-design methodology on Zynq platform.### Guides

- 📖 [Simulation Quick Start](docs/guides/Simulation_Quickstart.md) - Run your first simulation

---- 📖 [Vivado Synthesis Guide](docs/guides/Vivado_Synthesis.md) - Generate bitstream

- 📖 [PYNQ Deployment Guide](docs/guides/PYNQ_Deployment.md) - Deploy to hardware

## 📝 Key Learnings- 📖 [Waveform Analysis Guide](docs/guides/Waveform_Analysis.md) - Debug with GTKWave



✅ **RTL Design:** FSM implementation, AXI protocol, memory controller design  ### Tutorials

✅ **Verification:** Testbench development, waveform debugging, coverage analysis  - 🎓 [Complete Workflow](docs/tutorials/Complete_Workflow.md) - End-to-end process

✅ **Integration:** PS-PL interfaces, DMA configuration, interrupt handling  - 🎓 [System Overview](docs/tutorials/System_Overview.md) - How it works

✅ **Optimization:** Pipeline design, resource sharing, timing closure  - 🎓 [Signal Reference](docs/tutorials/Signal_Reference.md) - Signal descriptions

✅ **Deployment:** Bitstream generation, Python driver, Jupyter integration  

### API Documentation

---- 📘 [CSR Register Map](docs/api/register_map.md) - Control/status registers

- 📘 [Python Driver API](docs/api/python_driver.md) - PYNQ interface

## 📄 License

---

MIT License - See [LICENSE](LICENSE) file for details

## 🧪 Verification

---

### Simulation Results

## 🙏 Acknowledgments

| Testbench | Nodes | Edges | Pass? | Time |

- **Roji Ma'am** - Project guidance and mentorship|-----------|-------|-------|-------|------|

- **SRM University ECE Department** - Resources and support| `shortest_path_bfs_tb` | 29 | 114 | ✅ | 8.6ms |

- **Xilinx/AMD** - PYNQ framework and development tools| `system_tb` | 32 | 140 | ✅ | 8.9ms |

- **Open-source community** - Icarus Verilog and GTKWave| `celebrity_handler_tb` | 50 | 500 | ✅ | 52ms |



---### Waveform Verification

- ✅ FSM state transitions (IDLE→INIT→PROCESS→DONE)

## 📞 Contact- ✅ AXI handshake protocols (AWVALID/AWREADY, WVALID/WREADY)

- ✅ Node visit counters (0→29 increments)

**GitHub:** [@yourusername](https://github.com/yourusername)  - ✅ Edge scan counters (0→114 increments)

**LinkedIn:** [Your LinkedIn](https://linkedin.com/in/yourprofile)  - ✅ Interrupt generation on completion

**Email:** your.email@example.com

**Example waveform:**

---![BFS Waveform](docs/images/bfs_waveform.png)



## ⭐ Star This Repository---



If you find this project useful for learning FPGA design or graph algorithms, please consider giving it a star! ⭐## 🛠️ Development Setup



---### Tools Required

```bash

<p align="center"># Simulation

  <b>Built with ❤️ for hardware acceleration and graph processing</b>sudo apt install iverilog gtkwave

</p>

# Python environment

<p align="center">pip install pynq numpy matplotlib

  <img src="https://img.shields.io/github/stars/yourusername/zynq-bfs-accelerator?style=social" alt="Stars">

  <img src="https://img.shields.io/github/forks/yourusername/zynq-bfs-accelerator?style=social" alt="Forks"># FPGA synthesis (optional - for hardware deployment)

</p># Download Xilinx Vivado from xilinx.com

```

### Build from Source
```bash
# Compile with Icarus Verilog
cd sim/iverilog
iverilog -o bfs_sim -f ../filelist.f ../../tb/shortest_path_bfs_tb.v

# Run simulation
vvp bfs_sim

# View waveforms
gtkwave bfs_system_complete.vcd
```

---

## 🤝 Contributing

Contributions are welcome! Please feel free to submit issues and pull requests.

### Development Guidelines
- Follow Verilog-2001 coding style
- Add testbenches for new modules
- Update documentation for interface changes
- Run simulations before committing

---

## 📄 License

This project is licensed under the MIT License - see [LICENSE](LICENSE) file for details.

---

## 👥 Authors

**Team:**
- [@yourusername](https://github.com/yourusername) - RTL Design & Verification
- **Karthikeya** - System Integration & Testing
- **Akarsh** - FPGA Deployment & Optimization

**Mentor:**
- **Roji Ma'am** - Project Guidance

**Institution:**
- Department of Electronics and Communication Engineering
- SRM University

---

## 🙏 Acknowledgments

- **SRM University ECE Department** for providing resources and support
- **Roji Ma'am** for invaluable mentorship throughout the project
- **Xilinx/AMD** for PYNQ framework and development tools
- **Open-source community** for Icarus Verilog and GTKWave

---

## 📞 Contact

For questions or collaboration:
- 📧 Email: your.email@example.com
- 💼 LinkedIn: [Your LinkedIn Profile](https://linkedin.com/in/yourprofile)
- 🐙 GitHub: [@yourusername](https://github.com/yourusername)

---

## ⭐ Star History

If you find this project helpful, please consider giving it a star! ⭐

---

## 📊 Project Stats

![GitHub repo size](https://img.shields.io/github/repo-size/yourusername/fpga-bfs-accelerator)
![GitHub stars](https://img.shields.io/github/stars/yourusername/fpga-bfs-accelerator)
![GitHub forks](https://img.shields.io/github/forks/yourusername/fpga-bfs-accelerator)
![GitHub issues](https://img.shields.io/github/issues/yourusername/fpga-bfs-accelerator)

---

<p align="center">
  <b>Built with ❤️ for the FPGA and hardware acceleration community</b>
</p>
