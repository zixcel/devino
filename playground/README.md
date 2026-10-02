# Exams Playground to Use LLMs on My Local PC (Intel Iris GPU)

## Overview

This guide provides a general approach for individuals who do not own an Nvidia GPU and wish to perform inference using an integrated laptop GPU.

The goal is to enable local execution of LLMs casual without modifying existing development environments or considering the purchase of a new PC.

## Result Summary

By enabling GPU acceleration, performance improved by **5.7x**.

```
vscode ➜ /workspaces/devino (main) $ python playground/inference/roberta_text_classification.py
Function 'infer_with_transformer' executed in 9.391381 seconds
Function 'infer_with_openvino' executed in 1.628792 seconds
Transformer Model Prediction:
1) neutral 0.703
2) positive 0.2633
3) negative 0.0337

OpenVINO Model Prediction:
1) neutral 0.7033
2) positive 0.2629
3) negative 0.0338
```

## Exams Outline

* **Recognizing the GPU Driver**
  * **Windows**
    * Set up the GPU driver on the PC
  * **Docker**
    * Verify GPU driver recognition using Docker CLI
    * Check GPU driver recognition with Docker Desktop WSL Integration
* **Download LLMs**
  * Not Available quantize int4
    * https://github.com/openvinotoolkit/openvino/pull/29067
* **Obtaining and Converting LLMs**
  * Download from Hugging Face
  * Export to OpenVINO (IR) format
    * https://docs.openvino.ai/2025/openvino-workflow/running-inference/optimize-inference/optimizing-memory-usage.html
* **Inference**
  * Text Classification
  * Text Generation
    * https://docs.openvino.ai/2023.3/openvino_docs_OV_Converter_UG_prepare_model_convert_model_Convert_Model_From_ONNX.html

## How to Use This Repository

### Tools Setup
* Install [VSCode](https://code.visualstudio.com/)
* Install [Docker Desktop](https://www.docker.com/get-started/)
* Install [Git for Windows](https://git-scm.com/downloads/win)
* Install Intel GPU Driver ([Detail PC Specification](?tab=readme-ov-file#pc-specifications))

### Container Build
* Clone This Repo and Open in VSCode
  * ```git clone https://github.com/zixcel/devino.git```
  * ```code devino```
* Decide Mount Directory for LLMs
  * Modify [Devcontainer JSON](.devcontainer/devcontainer.json)
* Build Devcontainer

### Run scripts in Devcontainer

ex) Check the GPU driver is recognized

```
vscode ➜ /workspaces/devino (main) $ python playground/gpu_devices.py 
# ['CPU', 'GPU']
```

if it shows CPU only, GPU Driver invalid setup. 

## Details

### PC Specifications

It's the spec I tried, but if you have newer than 11th generation Intel CPU and GPU emdebed, it should work the same.

Detail compatibility can see [openvino/system-requirements](https://docs.openvino.ai/2025/about-openvino/release-notes-openvino/system-requirements.html)

* **OS:** Windows 11 Home 24H2
    * **Memory:** 16GB
    * **CPU:** [12th Gen Intel(R) Core(TM) i5-1235U 1.30 GHz](https://www.intel.com/content/www/us/en/products/sku/226261/intel-core-i51235u-processor-12m-cache-up-to-4-40-ghz/specifications.html)
        * **GPU:** Intel(R) Iris(R) Xe Graphics

### Runtime Environment

* **Docker Desktop**
    * WSL integration enabled to use the default WSL distribution
* **Docker (including Devcontainer)**
    * Debian Bookworm with Python 3.11 (Devcontainer uses the official Microsoft Python container)

### Model Sources Download

* **Hugging Face**
  * `transformers`
  * `huggingface_hub`

```
2025-03-08 13:03:05.147523: I tensorflow/core/platform/cpu_feature_guard.cc:210] This TensorFlow binary is optimized to use available CPU instructions in performance-critical operations.
To enable the following instructions: AVX2 AVX_VNNI FMA, in other operations, rebuild TensorFlow with the appropriate compiler flags.
config.json: 100%|██████████████████████████████████████████████████████████████████████████████████████████████████████████████████████████████████████| 802/802 [00:00<00:00, 3.91MB/s]
Traceback (most recent call last):
  File "/workspaces/devino/playground/inference/ms_phi4_text_generation.py", line 3, in <module>
    pipeline = transformers.pipeline(
               ^^^^^^^^^^^^^^^^^^^^^^
  File "${HOME}/.local/lib/python3.11/site-packages/transformers/pipelines/__init__.py", line 940, in pipeline
    framework, model = infer_framework_load_model(
                       ^^^^^^^^^^^^^^^^^^^^^^^^^^^
  File "${HOME}/.local/lib/python3.11/site-packages/transformers/pipelines/base.py", line 289, in infer_framework_load_model
    model = model_class.from_pretrained(model, **kwargs)
            ^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^^
  File "${HOME}/.local/lib/python3.11/site-packages/transformers/models/auto/auto_factory.py", line 564, in from_pretrained
    return model_class.from_pretrained(
           ^^^^^^^^^^^^^^^^^^^^^^^^^^^^
  File "${HOME}/.local/lib/python3.11/site-packages/transformers/modeling_utils.py", line 3535, in from_pretrained
    raise ImportError(
ImportError: Using `low_cpu_mem_usage=True` or a `device_map` requires Accelerate: `pip install 'accelerate>=0.26.0'`
```


### Additional Tools & Keywords

* Intel GPU Driver
* OpenVINO
* optimum-intel
  * https://huggingface.co/blog/deploy-with-openvino

other keywords see [glossary doc](https://huggingface.co/docs/transformers/main/en/glossary) by huggingface.

**Note:**  
Refer to the [2025 OpenVINO documentation](https://docs.openvino.ai/2025/index.html) for the latest installation methods.

