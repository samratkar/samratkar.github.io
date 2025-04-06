---
layout : mermaid
type : concept
title : "Attention - An overview"
---
{% capture my_markdown %}
{% include test.md %}
{% endcapture %}
{{ my_markdown | markdownify }}

## The main idea of attention
The evolution of NLP has been as follows -
![](/images/genai/chronology.svg) 

|**Date** | **Model** | **Description** |
|---------|-----------|------------------|
1966 | Eliza | First chatbot |
1980s | RNN | last hidden state would have the compressed past context |
1997 | LSTM | The long term cell state will give equal importance to all the past hidden states|
2014 | Bahdanau Attention | **Attention** + RNN (RNN was used for both encoder and decoder) |
2017 | **Attention** + **Transformer** | **RNN was removed** and Transformer was introduced. But it had again both **encoder and decoder.** **BERT** is an example for encoder + decoder architecture. [BERT paper](https://arxiv.org/abs/1810.04805) |
2018 | **Attention** + **General Purpose Transformer** | **No Encoder. Only decoder**. Encoder as a separate block was removed from original transformer|

### RNN - Recurrent Neural Networks
**RNNs**: [Recurrent Neural Networks (RNNs)](https://samratkar.github.io/2025/02/01/RNN-theo.html) were the first to be used for sequence-to-sequence tasks, but they struggled with long-range dependencies.
![ ](/images/genai/rnn-unrolled.svg)
<details>
  <summary>Click to expand</summary>
  <img src="/images/genai/rnn-block.svg" alt="Description" width="300">
</details>

### LSTM - Long Short-Term Memory

**LSTM**: [Long Short-Term Memory (LSTM)](https://samratkar.github.io/2025/02/15/LSTM-theory.html) networks improved upon RNNs by introducing memory cells and gates, allowing them to capture long-range dependencies more effectively. But still the problem was that all the previous hidden states were used to generate the next hidden state, which made it difficult to focus on specific parts of the input sequence.
<details>
   <summary>Click to expand</summary>
      <video width="640" height="360" controls>
         <source src="/images/genai/lstm-visualization.mp4" type="video/mp4">
         Your browser does not support the video tag.
      </video>
</details>

### Attention Mechanism
#### Bhadanau Attention 
[Bhadanav attention](/assets/genai/attention/sub-notes/bhadanau-attention.md)

### Self attention with trainable weights
![](/assets/genai/attention/sub-notes/self-attention.md)

## Multi-head attention
![](/assets/genai/attention/sub-notes/multi-head-attention.md)

## Layer normalization
![](/assets/genai/attention/sub-notes/layer-normalization.md)

## Feed-forward Neural Network
![](/assets/genai/attention/sub-notes/feedforward.md)


## All the illustrations and mindmaps referenced in this article : 
![](/assets/genai/attention/excalidraws/attention/attention.excalidraw.png)
## References

1. [What is the big deal about attention - vizuara substack](https://substack.com/inbox/post/158574020)
2. [Attention is all you need - arxiv](https://arxiv.org/abs/1706.03762)
3. Attention mechanism 1 hour video 
<iframe width="560" height="315" src="https://www.youtube.com/embed/K45ze9Yd5UE?si=FAJ3YPArq9Wu-uQ3" title="YouTube video player" frameborder="0" allow="accelerometer; autoplay; clipboard-write; encrypted-media; gyroscope; picture-in-picture; web-share" referrerpolicy="strict-origin-when-cross-origin" allowfullscreen></iframe>


