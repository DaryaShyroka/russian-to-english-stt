



# Milestone 2 Feedback:

### Like:

I like that you've kept things broad. I know that you're still working out the scope on things but you're definitely considering pros and cons of the different directions.
Great previous work section! You're way ahead on this part!
Data section is also solid. In fact the overall writing quality is good, you'll just need to update things based on what you finally decide to do.

### Questions:

Are you using a library to automatically calculate WER or are you writing a script to do this from scratch?  
IF you decide to do SLT, and also choose to do a pipeline/cascade approach will you use a Language Model or a alternatively a "spell checker" seq2seq model to improve performance?   (Note see how these do on your dev set before comitting to them necessarily for your final).  

### Recommended Next Steps / Direct Feedback:  

Decide scope (ASR/SLT, Fairseq vs. hugging face).  
Make sure you're prototyping things as you're going.

### Asides

I am leaning to suggest not use Fairseq's implementation ironically. The documentation is poor and there are issues with the pretrained models having keys incorrectly named which cause errors if you just try to load them directly. It can be somewhat frustrating if you try to do it, but might also be interesting. It would be the most 'reasonable' End-to-End system, although you might be able to jerry rig this in Hugging Face's implementation also.
