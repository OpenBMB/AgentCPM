<div align="center">
  <img src="../assets/AgentCPM-Report-logo.png" alt="AgentCPM-Report 标志" width="400em"></img>
</div>


<p align="center">
<a href='https://huggingface.co/openbmb/AgentCPM-Report'><img src='https://img.shields.io/badge/%F0%9F%A4%97%20Hugging%20Face-AgentCPM--Report-yellow'>
<a href='https://huggingface.co/openbmb/AgentCPM-Report-GGUF'><img src='https://img.shields.io/badge/%F0%9F%A4%97%20Hugging%20Face-AgentCPM--Report--GGUF-yellow'>
<a href='https://github.com/OpenBMB/UltraRAG'><img src='https://img.shields.io/badge/GitHub-UltraRAG-blue?logo=github'>
<a href='https://arxiv.org/abs/2602.06540'><img src='https://img.shields.io/badge/arXiv-2602.06540-red'>
</p>

<p align="center">
    【中文 | <a href="./README.md"><b>English</b></a>】
</p>

## 新闻
- [2026-01-20] 🚀🚀🚀我们开源了基于MiniCPM4.1-8B构建的AgentCPM-Report，能够在报告生成领域比肩顶尖的闭源商业系统如Gemini-2.5-pro-DeepResearch
## 概述
AgentCPM-Report是由[THUNLP](https://nlp.csai.tsinghua.edu.cn)、中国人民大学[RUCBM](https://github.com/RUCBM)和[ModelBest](https://modelbest.cn/en)联合开发的开源大语言模型智能体。它基于[MiniCPM4.1](https://github.com/OpenBMB/MiniCPM) 80亿参数基座模型，接受用户指令作为输入，自主生成长篇报告。其有以下亮点：

- 极致效能，以小博大：通过平均40轮的深度检索与近100轮的思维链推演，实现对信息的全方位挖掘与重组，让端侧模型也能产出逻辑严密、洞察深刻的万字长文，在深度调研任务上以8B参数规模达成与顶级闭源系统的性能对标。
- 物理隔绝，本地安全：专为高隐私场景设计，支持完全离线的本地化敏捷部署，彻底杜绝云端泄密风险。基于我们的 UltraRAG 框架，它能高效挂载并理解您的本地私有知识库，让核心机密数据在“不出域”的前提下，安全地转化为极具价值的专业决策报告。

## 演示案例：
<div align="center">
  <a href="https://www.bilibili.com/video/BV1DYkLBNE6f"><img src="https://i0.hdslb.com/bfs/archive/05f18d5914b8691316161021298a5b63da54eaeb.jpg", width=70%></a>
</div>

## 快速开始
### Docker部署
<div align="center">
  <a href="https://www.bilibili.com/video/BV1Kfk5BtEbG"><img src="http://i1.hdslb.com/bfs/archive/614883b2cf7ada53ade878e4baaad821c5f25a8c.jpg", width=70%></a>
</div>


我们实现了一个最简单的docker-compose一键部署，集成进了UltraRAG，包含RAG框架UltraRAG2.0，模型推理框架vllm与向量数据库milvus；如果您想使用cpu推理，我们也有使用llama.cpp对gguf格式文件模型的版本，将`docker-compose.yml`转成`docker-compose.cpu.yml`即可。

``` bash
git clone git@github.com:OpenBMB/UltraRAG.git
cd UltraRAG
git checkout agentcpm-report-demo
cd agentcpm-report-demo
cp env.example .env
docker-compose -f docker-compose.yml up -d --build
docker-compose -f docker-compose.yml logs -f ultrarag-ui
``` 
第一次启动需要拉取镜像，下载模型并配环境，需要稍等约30分钟左右
之后您打开`http:/localhost:5050` ，如果能看到图形界面，则说明您部署成功。
您可以遵循界面指示，上传本地文件，并进行切片，建索引；之后在Chat板块pipeline选择AgentCPM-Report开始您的流程！

（可选）您可以从[Wiki2024](https://modelscope.cn/datasets/UltraRAG/UltraRAG_Benchmark/tree/master/corpus/wiki24) 导入Wiki2024作为写作数据库。

您可以从[教程](https://ultrarag.openbmb.cn/pages/cn/demo/deepresearch) 中阅读更多关于AgentCPM-Report的教程。

#### Huggingface不可用时

Huggingface无法访问时，您可以通过[modelscope](https://modelscope.cn/models/OpenBMB/AgentCPM-Report)离线下载好模型放到UltraRAG/agentcpm-report-demo/models/agentcpm-report中，然后在.env中设置为本地路径：
```
VLLM_MODEL_HOST_PATH=
VLLM_MODEL_CONTAINER_PATH=/models/agentcpm-report
VLLM_MODEL=/models/agentcpm-report
VLLM_SERVED_MODEL_NAME=agentcpm-report
```

### 代码结构
```
AgentCPM-Report/
├── agentcpm-report-demo/  # 包含一键部署的docker-compose配置
├── examples/              # 包含AgentCPM-Report的配置文件示例
├── prompts/               # 包含报告生成所需的Prompt模板
├── servers/               # 自定义服务实现（主要是AgentCPM-Report管线）
└── UltraRAG/              # 部署框架UltraRAG，已经融合进部署相关内容
```

## 评估
<table align="center">
  <thead>
    <tr>
      <th align="center">DeepResearch Bench</th>
      <th align="center">Overall</th>
      <th align="center">Comprehensiveness</th>
      <th align="center">Insight</th>
      <th align="center">Instruction Following</th>
      <th align="center">Readability</th>
    </tr>
  </thead>
  <tbody>
    <tr>
      <td align="center">Doubao-research</td>
      <td align="center">44.34</td>
      <td align="center">44.84</td>
      <td align="center">40.56</td>
      <td align="center">47.95</td>
      <td align="center">44.69</td>
    </tr>
    <tr>
      <td align="center">Claude-research</td>
      <td align="center">45.00</td>
      <td align="center">45.34</td>
      <td align="center">42.79</td>
      <td align="center">47.58</td>
      <td align="center">44.66</td>
    </tr>
    <tr>
      <td align="center">OpenAI-deepresearch</td>
      <td align="center">46.45</td>
      <td align="center">46.46</td>
      <td align="center">43.73</td>
      <td align="center">49.39</td>
      <td align="center">47.22</td>
    </tr>
    <tr>
      <td align="center">Gemini-2.5-Pro-deepresearch</td>
      <td align="center">49.71</td>
      <td align="center">49.51</td>
      <td align="center">49.45</td>
      <td align="center">50.12</td>
      <td align="center">50.00</td>
    </tr>
    <tr>
      <td align="center">WebWeaver(Qwen3-30B-A3B)</td>
      <td align="center">46.77</td>
      <td align="center">45.15</td>
      <td align="center">45.78</td>
      <td align="center">49.21</td>
      <td align="center">47.34</td>
    </tr>
    <tr>
      <td align="center">WebWeaver(Claude-Sonnet-4)</td>
      <td align="center">50.58</td>
      <td align="center">51.45</td>
      <td align="center">50.02</td>
      <td align="center">50.81</td>
      <td align="center">49.79</td>
    </tr>
    <tr>
      <td align="center">Enterprise-DR(Gemini-2.5-Pro)</td>
      <td align="center">49.86</td>
      <td align="center">49.01</td>
      <td align="center">50.28</td>
      <td align="center">50.03</td>
      <td align="center">49.98</td>
    </tr>
    <tr>
      <td align="center">RhinoInsigh(Gemini-2.5-Pro)</td>
      <td align="center">50.92</td>
      <td align="center">50.51</td>
      <td align="center">51.45</td>
      <td align="center">51.72</td>
      <td align="center">50.00</td>
    </tr>
    <tr>
      <td align="center">AgentCPM-Report</td>
      <td align="center">50.11</td>
      <td align="center">50.54</td>
      <td align="center">52.64</td>
      <td align="center">48.87</td>
      <td align="center">44.17</td>
    </tr>
  </tbody>
</table>



<table align="center">
  <thead>
    <tr>
      <th align="center">DeepResearch Gym</th>
      <th align="center">Avg.</th>
      <th align="center">Clarity</th>
      <th align="center">Depth</th>
      <th align="center">Balance</th>
      <th align="center">Breadth</th>
      <th align="center">Support</th>
      <th align="center">Insightfulness</th>
    </tr>
  </thead>
  <tbody>
    <tr>
      <td align="center">Doubao-research</td>
      <td align="center">84.46</td>
      <td align="center">68.85</td>
      <td align="center">93.12</td>
      <td align="center">83.96</td>
      <td align="center">93.33</td>
      <td align="center">84.38</td>
      <td align="center">83.12</td>
    </tr>
    <tr>
      <td align="center">Claude-research</td>
      <td align="center">80.25</td>
      <td align="center">86.67</td>
      <td align="center">96.88</td>
      <td align="center">84.41</td>
      <td align="center">96.56</td>
      <td align="center">26.77</td>
      <td align="center">90.22</td>
    </tr>
    <tr>
      <td align="center">OpenAI-deepresearch</td>
      <td align="center">91.27</td>
      <td align="center">84.90</td>
      <td align="center">98.10</td>
      <td align="center">89.80</td>
      <td align="center">97.40</td>
      <td align="center">88.40</td>
      <td align="center">89.00</td>
    </tr>
    <tr>
      <td align="center">Gemini-2.5-pro-deepresearch</td>
      <td align="center">96.02</td>
      <td align="center">90.71</td>
      <td align="center">99.90</td>
      <td align="center">93.37</td>
      <td align="center">99.69</td>
      <td align="center">95.00</td>
      <td align="center">97.45</td>
    </tr>
    <tr>
      <td align="center">WebWeaver (Qwen3-30b-a3b)</td>
      <td align="center">77.27</td>
      <td align="center">71.88</td>
      <td align="center">85.51</td>
      <td align="center">75.80</td>
      <td align="center">84.78</td>
      <td align="center">63.77</td>
      <td align="center">81.88</td>
    </tr>
    <tr>
      <td align="center">WebWeaver (Claude-sonnet-4)</td>
      <td align="center">96.77</td>
      <td align="center">90.50</td>
      <td align="center">99.87</td>
      <td align="center">94.30</td>
      <td align="center">100.00</td>
      <td align="center">98.73</td>
      <td align="center">97.22</td>
    </tr>
    <tr>
      <td align="center">AgentCPM-Report</td>
      <td align="center">98.48</td>
      <td align="center">95.10</td>
      <td align="center">100.00</td>
      <td align="center">98.50</td>
      <td align="center">100.00</td>
      <td align="center">97.30</td>
      <td align="center">100.00</td>
    </tr>
  </tbody>
</table>

<table align="center">
  <thead>
    <tr>
      <th align="center">DeepConsult</th>
      <th align="center">Avg.</th>
      <th align="center">Win</th>
      <th align="center">Tie</th>
      <th align="center">Lose</th>
    </tr>
  </thead>
  <tbody>
    <tr>
      <td align="center">Doubao-research</td>
      <td align="center">5.42</td>
      <td align="center">29.95</td>
      <td align="center">40.35</td>
      <td align="center">29.70</td>
    </tr>
    <tr>
      <td align="center">Claude-research</td>
      <td align="center">4.60</td>
      <td align="center">25.00</td>
      <td align="center">38.89</td>
      <td align="center">36.11</td>
    </tr>
    <tr>
      <td align="center">OpenAI-deepresearch</td>
      <td align="center">5.00</td>
      <td align="center">0.00</td>
      <td align="center">100.00</td>
      <td align="center">0.00</td>
    </tr>
    <tr>
      <td align="center">Gemini-2.5-Pro-deepresearch</td>
      <td align="center">6.70</td>
      <td align="center">61.27</td>
      <td align="center">31.13</td>
      <td align="center">7.60</td>
    </tr>
    <tr>
      <td align="center">WebWeaver(Qwen3-30B-A3B)</td>
      <td align="center">4.57</td>
      <td align="center">28.65</td>
      <td align="center">34.90</td>
      <td align="center">36.46</td>
    </tr>
    <tr>
      <td align="center">WebWeaver(Claude-Sonnet-4)</td>
      <td align="center">6.96</td>
      <td align="center">66.86</td>
      <td align="center">10.47</td>
      <td align="center">22.67</td>
    </tr>
    <tr>
      <td align="center">Enterprise-DR(Gemini-2.5-Pro)</td>
      <td align="center">6.82</td>
      <td align="center">71.57</td>
      <td align="center">19.12</td>
      <td align="center">9.31</td>
    </tr>
    <tr>
      <td align="center">RhinoInsigh(Gemini-2.5-Pro)</td>
      <td align="center">6.82</td>
      <td align="center">68.51</td>
      <td align="center">11.02</td>
      <td align="center">20.47</td>
    </tr>
    <tr>
      <td align="center">AgentCPM-Report</td>
      <td align="center">6.60</td>
      <td align="center">57.60</td>
      <td align="center">13.73</td>
      <td align="center">28.68</td>
    </tr>
  </tbody>
</table>


我们的评测数据集包括DeepResearch Bench， DeepConsult和DeepResearch Gym，写作时知识库包括约270万[Arxiv论文](https://www.kaggle.com/api/v1/datasets/download/Cornell-University/arxiv)以及内部的约20万条网页总结。

## 致谢
本项目的实现离不开开源社区的支持与贡献。我们在开发过程中参考并使用了多个优秀的开源框架、模型和数据资源，包括[verl](https://github.com/volcengine/verl)、[UltraRAG](https://github.com/OpenBMB/UltraRAG)、[MiniCPM4.1](https://github.com/OpenBMB/MiniCPM)、[SurveyGo](https://surveygo.modelbest.cn/)

## 贡献

项目负责人：李奕杉，陈文通

项目贡献者：李奕杉，陈文通，闫宇坤，李明蔚，梅森，王晓荣，刘鲲鹏，从鑫，王硕，张众，卢雅西，刘正皓，林衍凯，刘知远，孙茂松

项目指导人：闫宇坤，林衍凯，刘知远，孙茂松

## 引用

如果 **AgentCPM-Report** 对您的研究有所帮助，您可以按照如下方式进行引用：

```bibtex
@misc{li2026agentcpmreport,
      title={AgentCPM-Report: Interleaving Drafting and Deepening for Open-Ended Deep Research}, 
      author={Yishan Li and Wentong Chen and Yukun Yan and Mingwei Li and Sen Mei and Xiaorong Wang and Kunpeng Liu and Xin Cong and Shuo Wang and Zhong Zhang and Yaxi Lu and Zhenghao Liu and Yankai Lin and Zhiyuan Liu and Maosong Sun},
      year={2026},
      eprint={2602.06540},
      archivePrefix={arXiv},
      primaryClass={cs.AI},
      url={https://arxiv.org/abs/2602.06540}, 
}
```
