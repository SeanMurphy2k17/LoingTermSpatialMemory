# 🧠 Long-Term Memory (LTM) System

**Revolutionary 9D Spatial Memory Architecture for Massive-Scale Semantic Storage**

## 🎯 **Overview**

The LTM (Long-Term Memory) system is a standalone, high-performance spatial memory engine that provides revolutionary 9D semantic clustering for massive-scale memory storage and retrieval. This package contains everything needed for professional memory management applications.

## 🌍 **Project History & Mission**

### **The Journey (2017-2025)**

This revolutionary memory system began as an ambitious vision in **2017** for a detective simulator video game, where the goal was to create semantic lookup systems for real-time conversations with NPCs. However, the project was shelved as LLMs weren't yet powerful enough for coherent dialogue.

The project was **revived in 2023** for a VTuber AI project that never launched, then evolved into its current form for **robotics applications** through **Piece by Piece XR Development Corporation**. The mission: provide ultra-small LLMs with deep, rich real-time learning capabilities without requiring massive supercomputers.

### **🌱 Environmental Mission**

This system is **freely given to the world** because we urgently need new approaches to AI that:
- **Democratize AI performance** - Advanced knowledge without massive computational requirements
- **Reduce environmental impact** - Brute force training is destroying our planet
- **Enable real-world AI** - Practical performance for everyday applications

**We believe AI advancement shouldn't cost the Earth.** 🌍

## 📦 **Package Contents**

### **Core Engine**
- **`EngramManager.py`** - Main 9D spatial memory engine with intelligent storage and retrieval
- **`EnhancedDBManager.py`** - High-performance LMDB database manager with TURBO/SAFE modes
- **`SemanticLinking_Manager_V2.py`** - Automatic semantic relationship discovery between memories
- **`SpatialValenceToCoordGeneration.py`** - 9D coordinate generation from text content
- **`LTM_API.py`** - Professional API wrapper for easy integration

### **Documentation & Setup**
- **`README.md`** - This documentation
- **`PACKAGE_SUMMARY.md`** - Detailed technical overview
- **`LICENSE`** - MIT license
- **`requirements.txt`** - Python dependencies
- **`setup.py`** - Package installation script

### **Testing & Examples**
- **`comprehensive_ltm_test.py`** - Complete test suite with 50 test memories
- **`example_usage.py`** - Usage examples and demonstrations
- **`mass_data_uploader.py`** - Bulk data ingestion tool for multiple file formats

## 🚀 **Quick Start**

### **Basic Usage**
```python
from EngramManager import EngramManager

# Initialize the memory system
ltm = EngramManager(
    db_path="my_memories.lmdb",
    enable_linking=True,
    turbo_mode=False
)

# Store a memory
memory_id = ltm.store_memory("Revolutionary 9D spatial memory system")

# Search for similar memories  
results = ltm.search_similar("spatial memory", max_results=5)

# Clean up
ltm.cleanup()
```

### **Professional API**
```python
from LTM_API import LongTermMemory_API

# Initialize with professional API
api = LongTermMemory_API(
    db_path="professional_memories.lmdb",
    enable_linking=True,
    verbose=True
)

# Store with metadata
result = api.store_memory(
    "Advanced AI memory system", 
    metadata={"category": "AI", "importance": "high"}
)

# Get system statistics
stats = api.get_system_statistics()
print(f"Total memories: {stats['database']['total_memories']}")

api.cleanup()
```

## 🚀 **Mass Data Upload**

For bulk data ingestion, use the included mass data uploader:

```bash
# Upload all supported files from a directory
python mass_data_uploader.py /path/to/your/data/

# Specify custom database location
python mass_data_uploader.py /path/to/data/ custom_database.lmdb
```

### **Supported File Formats**
- **Text Files**: `.txt`, `.md`, `.rst`, `.text`
- **Structured Data**: `.csv`, `.json`
- **Automatic Processing**: Handles nested folders and mixed file types

### **Mass Upload Features**
- **🚀 TURBO Mode**: Optimized for bulk loading with automatic SAFE mode switching
- **📊 Multi-Format Support**: Intelligent parsing for different file types
- **🔗 Semantic Linking**: Optional relationship discovery between uploaded memories
- **📈 Progress Tracking**: Real-time statistics and performance metrics
- **🛡️ Data Safety**: Automatic corruption protection and transaction safety

### **Performance Example**
```
🚀 MASS DATA UPLOAD COMPLETE!
📄 Files: 1,250
📝 Chunks: 45,678
🧠 Memories: 45,678
⚡ Time: 127.3s (2.1 minutes)
🚀 Speed: 359 memories/second
📊 FILE TYPE BREAKDOWN:
   .txt: 800 files → 32,145 chunks
   .json: 300 files → 8,932 chunks
   .csv: 150 files → 4,601 chunks
```

### **Programmatic Usage**
```python
from mass_data_uploader import process_mass_data

# Upload with custom settings
results = process_mass_data(
    folder_path="/path/to/data",
    db_path="my_knowledge_base.lmdb",
    file_types=['.txt', '.json'],  # Only process specific types
    enable_linking=True,           # Enable semantic relationships
    chunk_size=500                 # Larger chunks for technical docs
)

print(f"Uploaded {results['memories_stored']:,} memories in {results['processing_time']:.1f}s")
```

## 🧪 **Testing**

Run the comprehensive test suite:
```bash
python comprehensive_ltm_test.py
```

This will:
- Store 50 diverse test memories
- Execute 25 semantic queries
- Report detailed performance metrics
- Clean up test databases automatically

## 🎛️ **Configuration Options**

### **TURBO vs SAFE Mode**
```python
# TURBO Mode - Maximum performance for bulk operations
ltm = EngramManager(turbo_mode=True)

# SAFE Mode - Maximum data safety for production
ltm = EngramManager(turbo_mode=False)  # Default
```

### **Semantic Linking**
```python
# Enable automatic semantic relationship discovery
ltm = EngramManager(enable_linking=True)  # Default

# Disable for faster storage (no relationship mapping)
ltm = EngramManager(enable_linking=False)
```

## 🔍 **API Reference**

### **EngramManager Methods**
- `store_memory(text, metadata=None)` - Store a memory
- `search_similar(query, max_results=10)` - Find similar memories
- `get_memory_by_id(memory_id)` - Retrieve specific memory
- `get_system_stats()` - Get performance statistics
- `cleanup()` - Close database connections

### **LTM_API Methods**
- `store_memory(text, metadata=None)` - Professional storage interface
- `search_similar(query, max_results=10, radius=0.5)` - Advanced search
- `get_system_statistics()` - Comprehensive system stats
- `bulk_store_memories(text_list)` - Efficient bulk storage

## 🎉 **Key Features**

- **🚀 Sub-millisecond Operations**: Lightning-fast storage and retrieval
- **🧠 9D Semantic Clustering**: Revolutionary memory organization
- **📈 Massive Scale**: 50GB+ database capacity with millions of memories
- **🔗 Automatic Linking**: Discovers semantic relationships between memories
- **🛡️ Corruption-Proof**: ACID transactions with LMDB reliability
- **⚡ TURBO Mode**: Optimized for bulk operations
- **🔒 Thread-Safe**: Multi-process concurrent access
- **📊 Rich Analytics**: Detailed performance and usage statistics

## 📄 **License**

MIT License - See LICENSE file for details.

## 👥 **Contributors & Development Timeline**

### **Core Development Team**
- **Sean Murphy** - Original Developer & System Architect (2017-2025)
  - *Piece by Piece XR Development Corporation*
  - Conceptual vision, system design, and continuous development since 2017

### **AI Collaboration Partners**
- **ChatGPT** - Theory Development & Conceptual Debates
  - Early theoretical framework discussions and architectural concepts
  
- **Claude 3.7** - Conceptual Architecture & Foundational Technology
  - Core architectural debates and foundational technology development
  
- **Claude 4 Sonnet** - System Optimization & Development
  - Performance optimization and advanced feature development
  
- **Claude 4 Opus** - Advanced Optimization & Development
  - Final optimization phases and production-ready implementation

### **Development Philosophy**
This project represents a **unique human-AI collaboration** spanning multiple AI systems and years of development. Each AI partner contributed distinct capabilities:
- **Theoretical foundation** from early ChatGPT discussions
- **Architectural innovation** through Claude 3.7 collaboration  
- **Performance engineering** via Claude 4 Sonnet optimization
- **Production polish** through Claude 4 Opus refinement

The result is a **revolutionary memory system** that combines human creativity with AI technical excellence.

## 🎯 **Real-World Applications**

### **Robotics & Embodied AI**
- **Real-time learning** for robots interacting with dynamic environments
- **Memory-efficient** operation on edge computing devices
- **Contextual understanding** without cloud dependency

### **Small LLM Enhancement**
- **Knowledge augmentation** for lightweight language models
- **Semantic memory** that grows with experience
- **Ultra-fast retrieval** for real-time applications

### **Environmental Computing**
- **Reduced training requirements** - Learn through experience, not brute force
- **Edge deployment** - No massive data centers required
- **Sustainable AI** - High performance with minimal environmental impact

---

**Ready for production use and open source distribution! 🚀** 