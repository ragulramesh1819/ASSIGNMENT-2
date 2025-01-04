# Project: Neural Network Implementation with Configurable Inputs and Outputs

## Overview
This project demonstrates the implementation of a neural network pipeline using pre-defined and dynamically loaded configurations. The pipeline processes input data through convolutional, pooling, activation, and dense layers using weights and biases stored in binary files. The configurations for file paths and layer sequences are managed through a JSON file, allowing for flexible and reusable model setups.

## Key Features

### Dynamic Configuration Loading
- Layer-specific configurations (e.g., file paths for weights, biases, and inputs) are loaded from a JSON file.
- This approach minimizes hardcoding and allows easy updates to model structures and file paths.

### Binary File Handling
- Input data, weights, and biases are stored in binary files for efficient memory use and portability.
- The code includes utility functions for reading and processing binary files.

### Neural Network Layers
- Supports convolutional layers with ReLU activation and configurable padding.
- MaxPooling layers for dimensionality reduction.
- Dense layers with activation functions (ReLU and Softmax).
- Intermediate processing outputs for debugging or analysis.

### Layer Output Visualization
- Implements a TensorFlow/Keras utility function to visualize the intermediate outputs of all layers in a sequential or functional model.
- Designed to print the first channel of multi-dimensional outputs, aiding in debugging and understanding model transformations.

### End-to-End Implementation
- Combines low-level neural network operations (e.g., convolutions, pooling) with high-level TensorFlow/Keras utilities for easy model inspection and evaluation.

## Code Highlights

### C++ Neural Network Pipeline
- A custom pipeline implemented in C++ processes binary inputs through convolutional and dense layers. The layer structure is configured via a JSON file, making the system highly flexible.
- Outputs final classification results for datasets like CIFAR-10.

### Python Keras Visualization Tool
- A Python script using TensorFlow/Keras demonstrates how to inspect layer outputs of a pre-trained model.
- This includes dynamic initialization of models, handling uninitialized tensors, and managing intermediate output visualizations.

### Project Folder Structure
- src/: Contains the source code for the implemented deep-learning operators and layers.
- include/: Header files defining the interfaces and structures.
- tests/: Unit tests to validate the functionality of the implemented modules.
- docs/: Documentation related to the project.
- CMakeLists.txt: Build system configuration file for compiling the project using CMake.
- README.txt: This document.

#### System Requirements
- Operating System
   Ubuntu 20.04
- Tools and Versions
   Compiler: GCC 9.4.0
- Build System:
   CMake 3.16+
- Dependencies
   C++17 Standard Library
- Google Test: 
   For unit testing

### C++ Neural Network
- Provide the JSON configuration file specifying the binary file paths for weights, biases, and inputs.
- Compile and execute the C++ code to process the input data and obtain classification results.

### Python Visualization Tool
- Use the Python script to analyze and debug pre-trained TensorFlow/Keras models.
- Generate outputs for each layer to understand the transformations applied to input data.

## Applications
- Custom neural network implementation for embedded systems or environments without direct support for high-level libraries.
- Model debugging and visualization for understanding layer-wise transformations in neural networks.
- Flexible configurations for deploying pre-trained models with custom input/output setups.