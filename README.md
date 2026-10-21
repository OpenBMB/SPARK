<!-- title -->
<div align="center">
<h1> SPARK: Adaptive Parametric Knowledge Participation for Faithful Retrieval-Augmented Generation
<h5 align="center"> 


<!-- hyperlinks -->
<p align="center">
  <a href="https://github.com/OpenBMB/SPARK" alt="GitHub">
    <img src="https://img.shields.io/badge/GitHub-SPARK-black?logo=github"/>
  </a>
  <a href="https://arxiv.org/abs/2606.27786" alt="Paper">
    <img src="https://img.shields.io/badge/Paper-SPARK-B31B1B?logo=arxiv&logoColor=white"/>
  </a>
  <a href="https://huggingface.co/ITcoder/SHIFT" alt="Checkpoints">
    <img src="https://img.shields.io/badge/Checkpoints-SPARK-yellowgreen?logo=huggingface"/>
  </a>
  <a href="LICENSE" alt="License">
    <img src="https://img.shields.io/badge/License-MIT-e8b500?logo=license"/>
  </a>
</p>


<!-- authors -->
Ruochang Li<sup>1*</sup>,
Pengcheng Huang<sup>1\*</sup>,
Zhenghao Liu<sup>1†</sup>,
Yukun Yan<sup>2</sup>,
</br>
Huiyuan Xie<sup>2</sup>,
Yu Gu<sup>1</sup>,
Ge Yu<sup>1</sup>,
Maosong Sun<sup>2</sup>

<sup>1</sup>Northeastern University, <sup>2</sup>Tsinghua University

</h5>
</div>


## 📖 Overview
<p align="center">
  <img src="figs/framework.png" alt="SPARK overview" width="95%">
</p>

SPARK is a lightweight framework that learns adaptive knowledge participation policies for faithful retrieval-augmented generation. With the backbone LLM frozen, its participation policy dynamically regulates layer-wise FFN contributions, determining when and to what extent parametric knowledge participates during generation. Optimized through faithfulness-guided reinforcement learning using response-level rewards, SPARK mitigates catastrophic forgetting and better preserves general generation capabilities compared to full-parameter supervised fine-tuning.

## ⚙️ Setup
1. Create Conda Environment
```bash
conda create --name spark python==3.10.0
conda activate spark
git clone https://github.com/OpenBMB/SPARK.git
cd SPARK
```
2. Install PyTorch
```
pip install torch==2.6.0 --index-url https://download.pytorch.org/whl/cu124
```
3. Install Flash Attention
```
pip install https://github.com/Dao-AILab/flash-attention/releases/download/v2.7.4.post1/flash_attn-2.7.4.post1+cu12torch2.6cxx11abiFALSE-cp310-cp310-linux_x86_64.whl
```
4. Install the rest of the dependencies
```
pip install -r requirements.txt
```
5. Patch vLLM model files  
This project requires modifications to the vLLM implementations of Qwen3 and LLaMA.
After installing the requirements, run the patch script:
```
bash vllm/patch_vllm.sh
```
> Note: Please run this script after 'pip install -r requirements.', because installing or reinstalling vLLM may overwrite the patched files.

### ⚡ Data
<!-- todo: 已创建repo, 数据待上传 -->

Our training data can be downloaded from [SPARK_Training_Data](https://huggingface.co/datasets/ITcoder/SPARK_Training_Data). After downloading, place the files into the dataset folder.


To construct the data from scratch, download the files from [MRQA-Shared-Task-2019](https://github.com/mrqa/MRQA-Shared-Task-2019).  
Use the downloaded data to synthesize it with [FlashRAG](https://github.com/RUC-NLPIR/FlashRAG).


### 🔥 Training
GRPO with a single GPU: 
```
python single_gpu.py
```
GRPO with multiple GPUs:
```
python multi_gpu.py
```


### 📊 Evaluation
<!-- todo: 更新最新的sft和spark的checkpoints: 1.7B 和 8B, 已创建repo, ckpt待上传-->

We provide the SFT checkpoints and the trained checkpoints(https://huggingface.co/ITcoder/SPARK) on Hugging Face.  

To evaluate on the MRQA and ConfiQA benchmarks: 
```
python eval.py
```
To evaluate on the MMLU benchmark, use [lm-evaluation-harness](https://github.com/EleutherAI/lm-evaluation-harness).  


### 🎯 Analysis

We also provide the t-SNE visualization pipeline for participation vectors in SPARK, with corresponding figures available under the figs folder:
```
python run_batch_tsne.py
```

For Qwen-3-1.7B: 
<p align="center">
  <img src="figs/qwen3-1.7B-tsne.png" alt=" Qwen-3-1.7B" width="50%">
</p>
For Qwen-3-8B:
<p align="center">
  <img src="figs/qwen3_8B_tsne.png" alt=" Qwen-3-8B" width="50%">
</p>



### 🎉 Acknowledgement 
Our work is built on the following codebases, and we are deeply grateful for their contributions.
- [vllm](https://github.com/vllm-project/vllm)
- [nano-aha-moment](https://github.com/McGill-NLP/nano-aha-moment)
- [lm-evaluation-harness](https://github.com/EleutherAI/lm-evaluation-harness)
- [gated_attention](https://github.com/qiuzh20/gated_attention)
- [FlashRAG](https://github.com/RUC-NLPIR/FlashRAG)
  


### 🥰 Citation

If you find this work useful, please cite our paper and give us a shining star 🌟
```bibtex
@misc{li2026sparkadaptiveparametricknowledge,
      title={SPARK: Adaptive Parametric Knowledge Participation for Faithful Retrieval-Augmented Generation}, 
      author={Ruochang Li and Pengcheng Huang and Zhenghao Liu and Yukun Yan and Huiyuan Xie and Yu Gu and Ge Yu and Maosong Sun},
      year={2026},
      eprint={2606.27786},
      archivePrefix={arXiv},
      primaryClass={cs.CL},
      url={https://arxiv.org/abs/2606.27786}, 
}
```


### 📧 Contact
If you have questions, collaboration opportunities, or potential PhD opportunities in the United States, please feel free to email:
```
ruochangli@gmail.com
```

