#🫁 Lungs Pneumonia Detection and Localization using Deep Learning

##🚀 Project Overview

This project applies Deep Learning and High-Performance Computing (HPC) to detect and localize pneumonia in chest X-ray (CXR) images.
It leverages Convolutional Neural Networks (CNNs) for classification and YOLOv8 for bounding-box localization, trained in both serial and parallel environments using multi-core CPUs and multi-GPU clusters.

Our work demonstrates how parallel computing accelerates AI model training while maintaining diagnostic accuracy — a crucial advancement for scalable medical image analysis.

> **Note:** This notebook was executed on a High-Performance Computing (HPC) cluster
> (Open OnDemand environment).  
> Some `!pip`, `%%writefile`, and environment setup cells are included intentionally
> to handle missing packages and cluster-specific initialization.  
> These are not errors they are part of the reproducibility steps for running on HPC.


##🎯 Objectives

Develop a robust deep learning pipeline to classify and localize pneumonia.
Implement and benchmark serial vs. parallel training using:
CPU parallelism via PyTorch DistributedDataParallel (DDP)
GPU parallelism via DDP and Fully Sharded Data Parallel (FSDP)

Evaluate the impact of HPC scaling on:

Training speed and throughput
Model accuracy, precision, recall, and mAP
Resource efficiency across CPUs and GPUs

##🧠 Methodology

1. Dataset

RSNA Pneumonia Detection Challenge dataset – 30,000+ expert-annotated chest X-rays.
Balanced classes (~12,000 total images) after validation and cleaning.

Preprocessing:

Image resizing (128×128 or 416×416 for YOLO)
Normalization and data augmentation (flips, brightness, gamma, noise)
Parallel metadata loading using Dask

2. Environment

Executed on an HPC cluster via Open OnDemand (OOD) Jupyter environment.
Used job scheduler for multi-node, multi-GPU training.
Frameworks: PyTorch, Dask, Albumentations, Ultralytics YOLOv8, OpenCV, Matplotlib.

3. Model Architecture
Task	Model	Description
Classification	Custom CNN	Two convolutional + two fully-connected layers (ReLU, max-pool, sigmoid)
Localization	YOLOv8 Nano	Pre-trained detection backbone fine-tuned on RSNA dataset

5. Parallelization Techniques

CPU DDP: Multi-process gradient synchronization via torch.multiprocessing (2–8 cores).
GPU DDP: Multi-GPU gradient sync using torchrun.
FSDP: Model sharding across 2–3 GPUs for memory efficiency and scalability.
Parallel I/O: DataLoader with multi-workers and Dask partitions to reduce bottlenecks.

##⚙️ Performance Highlights
Configuration	Training Time	Accuracy / mAP	Speedup	Efficiency
Serial CNN (CPU)	5530 s	87.2 %	1×	1.00
2-CPU DDP	3273 s	76 %	1.69×	0.84
4-CPU DDP	3056 s	77 %	1.81×	0.45
2-GPU DDP	2848 s	75.5 %	1.92×	0.38
3-GPU FSDP	3308 s	75.6 %	1.99×	0.33
YOLOv8 (4 GPU Parallel)	5208 s	mAP@0.5 = 0.149	—	—

##🧩 Parallelization significantly reduced training time (2× faster), though efficiency dropped beyond 4 CPUs due to synchronization overhead, consistent with Amdahl’s Law.

##🧩 HPC Environment Note

Note: These notebooks contain !pip, %%writefile, and other setup commands intentionally.
They were executed in an HPC cluster environment (Open OnDemand) where environment setup and dependency management were required dynamically.
These commands ensure reproducibility across cluster nodes and are not errors.


##🧮 Key Learnings

Parallelism boosts training efficiency but introduces synchronization overhead.
FSDP provides memory-efficient scaling across multiple GPUs.
YOLOv8 performs well on pneumonia localization, though bounding-box precision still depends on annotation quality.
The HPC framework provides realistic insight into production-grade distributed ML.

##🏁 Conclusion

This project successfully integrated High-Performance Computing with Deep Learning for medical imaging.
By combining parallel data handling, distributed training, and GPU acceleration, it achieved significant performance improvements without loss of model fidelity — demonstrating the feasibility of scalable, AI-driven medical diagnostics in HPC environments.
