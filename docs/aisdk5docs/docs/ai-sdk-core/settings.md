AI SDK 5 is available now.










Menu






















































































































































































































































































































































# [Settings](#settings)

Large language models (LLMs) typically provide settings to augment their output.

All AI SDK functions support the following common settings in addition to the model, the [prompt](../foundations/prompts.html), and additional provider-specific settings:



``` ts
const result = await generateText();
```





Some providers do not support all common settings. If you use a setting with a provider that does not support it, a warning will be generated. You can check the `warnings` property in the result object to see if any warnings were generated.



### [`maxOutputTokens`](#maxoutputtokens)

Maximum number of tokens to generate.

### [`temperature`](#temperature)

Temperature setting.

The value is passed through to the provider. The range depends on the provider and model. For most providers, `0` means almost deterministic results, and higher values mean more randomness.

It is recommended to set either `temperature` or `topP`, but not both.






### [`topP`](#topp)

Nucleus sampling.

The value is passed through to the provider. The range depends on the provider and model. For most providers, nucleus sampling is a number between 0 and 1. E.g. 0.1 would mean that only tokens with the top 10% probability mass are considered.

It is recommended to set either `temperature` or `topP`, but not both.

### [`topK`](#topk)

Only sample from the top K options for each subsequent token.

Used to remove "long tail" low probability responses. Recommended for advanced use cases only. You usually only need to use `temperature`.

### [`presencePenalty`](#presencepenalty)

The presence penalty affects the likelihood of the model to repeat information that is already in the prompt.

The value is passed through to the provider. The range depends on the provider and model. For most providers, `0` means no penalty.

### [`frequencyPenalty`](#frequencypenalty)

The frequency penalty affects the likelihood of the model to repeatedly use the same words or phrases.

The value is passed through to the provider. The range depends on the provider and model. For most providers, `0` means no penalty.

### [`stopSequences`](#stopsequences)

The stop sequences to use for stopping the text generation.

If set, the model will stop generating text when one of the stop sequences is generated. Providers may have limits on the number of stop sequences.

### [`seed`](#seed)

It is the seed (integer) to use for random sampling. If set and supported by the model, calls will generate deterministic results.

### [`maxRetries`](#maxretries)

Maximum number of retries. Set to 0 to disable retries. Default: `2`.

### [`abortSignal`](#abortsignal)

An optional abort signal that can be used to cancel the call.

The abort signal can e.g. be forwarded from a user interface to cancel the call, or to define a timeout.

#### [Example: Timeout](#example-timeout)



``` ts
const result = await generateText();
```


### [`headers`](#headers)

Additional HTTP headers to be sent with the request. Only applicable for HTTP-based providers.

You can use the request headers to provide additional information to the provider, depending on what the provider supports. For example, some observability providers support headers such as `Prompt-Id`.



``` ts
import  from 'ai';import  from '@ai-sdk/openai';
const result = await generateText(,});
```





The `headers` setting is for request-specific headers. You can also set `headers` in the provider configuration. These headers will be sent with every request made by the provider.


















On this page



















































Vercel delivers the infrastructure and developer experience you need to ship reliable AI-powered applications at scale.

Trusted by industry leaders:















#### Resources




#### More




#### About Vercel




#### Legal







© 2025 Vercel, Inc.